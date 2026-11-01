"""Self-learning module for sibyl-memory-client.

Mirrors the way SIBYL accumulates session memory into reusable skills:
scan the journal for repeating patterns, abstract them into structured
skill documents, and queue the proposals for user review.

THREE RUNTIME MODES (operator directive 2026-05-15)
===================================================

1. **local-deterministic** (default, free tier)
   Pure SQL + Python pattern detectors. No network, no LLM. Preserves the
   strict local-first promise. Produces skill bodies via deterministic
   templates from the matched event group.

2. **byok** (paid-tier opt-in)
   User pastes their own Anthropic / OpenAI / Venice key into config.
   The Learner uses the key to summarize matched event clusters into
   prose skill bodies. Local-first stays intact at the data layer -
   the user controls where the inference call goes. Sibyl Labs never
   sees the key or the payload.

3. **venice-x402** (paid-tier hosted, value-add for Venice partnership)
   User pre-funds their plugin account with FIAT or USDC. Sibyl Labs
   auto-routes inference via Venice + x402 against the user's funded
   balance from Sibyl's own infrastructure. Highest convenience, only
   the prompt summary leaves the device (never the underlying memory
   content). The Venice/x402 endpoint design is captured in the memo
   `memory/research/2026-05-15-self-learning-design.md`.

WHAT GETS DETECTED
==================

Four pattern kinds in v0.2.0:

| pattern_kind            | what it catches                                |
|-------------------------|------------------------------------------------|
| repeated_action         | same/similar `acted` payload across N events  |
| structural_similarity   | journal events with overlapping evaluated keys|
| temporal_routine        | events that fire at a stable cadence          |
| co_occurrence           | entities + actions that consistently appear   |
|                         | together in the same journal entries          |

Pattern detection is intentionally simple and explainable. Sophisticated
embedding-based clustering can land in v0.3.0 as an optional add-on.

REVIEW QUEUE
============

Detected patterns land in `skill_proposals` with status='pending'. The
public API exposes:

    list_proposals(status='pending', limit=N)
    accept_proposal(proposal_id, note=None)   → writes to reference_documents
    reject_proposal(proposal_id, note=None)
    get_proposal(proposal_id)

Accepted proposals create `reference_documents` rows keyed `skill/<slug>`.
"""
from __future__ import annotations

import json
import logging
import re
import sqlite3
from collections import Counter, defaultdict
from dataclasses import dataclass, field
from typing import Any, Callable, Iterable, Protocol

from .client import DEFAULT_TENANT
from .exceptions import NotFoundError, ValidationError
from .storage import Storage, _utc_now_iso, dumps, loads, new_id

logger = logging.getLogger(__name__)

# F6 (red-team 2026-06-17): cap the per-run journal scan. The journal grows
# unbounded (every turn appends); an uncapped SELECT + fetchall + 4-column JSON
# decode is a memory/CPU spike on a large journal. This is a DoS backstop, not a
# routine limit — the watermark (max scanned ts) advances each run, so a large
# backlog drains across runs instead of in one spike.
_MAX_EVENTS_PER_RUN = 10000

# R13 (super-patch 2026-07-05): the co-occurrence detector builds every 2-combo
# of an event's DISTINCT tokens (O(tokens²) per event). A single pathological
# event (a ≤1 MiB body can hold ~100k short strings → ~5e9 pairs) would hang the
# run — and spike memory — long before any ``min_hits`` threshold prunes it. Two
# cheap bounds close this: cap the distinct tokens considered per event, and cap
# the total distinct pairs tracked across the whole run. Realistic shallow events
# (a handful of keys / verbs) are far under both caps and behave identically.
_MAX_TOKENS_PER_EVENT = 64
_MAX_TRACKED_PAIRS = 100_000

# R1 (plugin paid tier, operator D7): a rejected slug is not proposed again for
# 30 days, and a slug rejected twice is muted until the person unmutes it.
REJECT_COOL_OFF_DAYS = 30
REJECT_MUTE_COUNT = 2


# ----------------------------------------------------------------------
# Public API surface
# ----------------------------------------------------------------------

@dataclass(frozen=True)
class SkillProposal:
    """Immutable view of a row in skill_proposals."""
    id: str
    tenant_id: str
    pattern_kind: str
    proposed_slug: str
    proposed_title: str | None
    proposed_body: str
    evidence: list[dict[str, Any]]
    confidence: float
    summarizer: str
    status: str
    created_at: str
    reviewed_at: str | None = None
    review_note: str | None = None
    accepted_doc_key: str | None = None


@dataclass
class LearningRunReport:
    """Per-invocation summary returned by Learner.run()."""
    run_id: str
    events_scanned: int
    proposals_made: int
    proposal_ids: list[str] = field(default_factory=list)
    started_at: str = ""
    completed_at: str = ""
    summarizer: str = ""
    # R2: the signals.json keys (n-gram keys, entity hashes) that became
    # proposals in this run, so the caller can mark them ``proposed_at``.
    signal_keys: list[str] = field(default_factory=list)


class Summarizer(Protocol):
    """Pluggable interface for converting a detected pattern into prose.

    Implementations must be synchronous and side-effect-free with respect
    to the local SQLite database. The Learner handles all persistence.
    """

    name: str

    def summarize(
        self,
        pattern_kind: str,
        events: list[dict[str, Any]],
        hints: dict[str, Any],
    ) -> tuple[str, str | None]:
        """Return (body_markdown, title_or_None) for the proposal."""
        ...


# ----------------------------------------------------------------------
# Local-deterministic summarizer (free-tier default)
# ----------------------------------------------------------------------

class LocalDeterministicSummarizer:
    """Generates skill bodies via templates, no LLM call.

    Useful properties:
      • Zero network. Free-tier-safe.
      • Deterministic: same input always produces the same body.
      • Explains its own reasoning (so the user sees why the pattern
        was surfaced).
    """

    name = "local-deterministic"

    def summarize(
        self,
        pattern_kind: str,
        events: list[dict[str, Any]],
        hints: dict[str, Any],
    ) -> tuple[str, str | None]:
        title = hints.get("title") or _slug_to_title(hints.get("slug", pattern_kind))
        lines: list[str] = []
        lines.append(f"# {title}")
        lines.append("")
        lines.append(f"_Auto-detected from {len(events)} matching journal events._")
        lines.append("")
        lines.append("## Pattern")
        lines.append("")
        if pattern_kind == "repeated_action":
            sample = hints.get("action_signature") or "(no action signature)"
            lines.append(f"Recurring action: `{sample}`")
        elif pattern_kind == "structural_similarity":
            keys = ", ".join(hints.get("shared_keys", []) or [])
            lines.append(f"Events consistently include input keys: `{keys}`")
        elif pattern_kind == "temporal_routine":
            cadence = hints.get("cadence_minutes")
            lines.append(
                f"Events fire at roughly stable cadence "
                f"(~{cadence} min between occurrences)."
                if cadence
                else "Events fire at a stable cadence."
            )
        elif pattern_kind == "co_occurrence":
            pair = hints.get("pair") or ("", "")
            lines.append(
                f"`{pair[0]}` and `{pair[1]}` consistently appear together in "
                f"the same journal entries."
            )
        elif pattern_kind in ("tool_sequence", "correction_loop"):
            return _signal_body(pattern_kind, events, hints, title), title
        else:
            lines.append("(pattern kind unrecognized: flagged for review)")

        lines.append("")
        lines.append("## Evidence")
        lines.append("")
        for ev in events[:5]:  # cap at five for readability
            ts = ev.get("ts") or "?"
            snippet = _short_event_snippet(ev)
            lines.append(f"- `{ts}`: {snippet}")
        if len(events) > 5:
            lines.append(f"- _…and {len(events) - 5} more matching events_")
        lines.append("")
        lines.append("## Suggested use")
        lines.append("")
        lines.append(
            "Reference this skill when the same situation recurs. "
            "Accept or reject it with `sibyl skills proposals`."
        )
        return "\n".join(lines), title


# ----------------------------------------------------------------------
# BYOK summarizer stub (paid-tier opt-in)
# ----------------------------------------------------------------------

class BYOKSummarizer:
    """User-supplied-key summarizer.

    The user passes a callable `inference_fn(prompt: str) -> str` so the
    SDK never holds the key itself. The callable can be implemented
    against Anthropic, OpenAI, Venice, or any provider: the SDK
    doesn't care.

    Free-tier installs cannot construct this class (the CLI's tier
    check happens upstream). v0.2.0 ships the wiring; the CLI gate
    enforces it.
    """

    def __init__(
        self,
        inference_fn: Callable[[str], str],
        *,
        provider_label: str = "byok",
    ) -> None:
        self._inference_fn = inference_fn
        self.name = f"byok-{provider_label}"

    def summarize(
        self,
        pattern_kind: str,
        events: list[dict[str, Any]],
        hints: dict[str, Any],
    ) -> tuple[str, str | None]:
        # BYOK keeps full event fidelity: the user controls where the
        # inference call goes (their own key / inference_fn), so raw memory
        # content never leaves their chosen destination by Sibyl's hand.
        prompt = _build_summarization_prompt(pattern_kind, events, hints, redact=False)
        try:
            body = self._inference_fn(prompt)
        except Exception as e:  # pragma: no cover
            # Fall back to deterministic if the user's key fails
            fallback = LocalDeterministicSummarizer()
            body, title = fallback.summarize(pattern_kind, events, hints)
            return body + f"\n\n---\n_Note: BYOK call failed ({e}). Using local fallback._", title
        title = hints.get("title") or _slug_to_title(hints.get("slug", pattern_kind))
        return body, title


# ----------------------------------------------------------------------
# Venice + x402 routed summarizer stub (paid-tier hosted)
# ----------------------------------------------------------------------

class VeniceX402Summarizer:
    """Routes inference through Venice via x402 against the user's
    pre-funded Sibyl Labs plugin balance.

    The actual network call lives behind `inference_fn` so this module
    stays HTTP-library-free. The CLI layer (sibyl-labs-cli) provides
    the real fn that signs an x402 payment header, hits the Sibyl
    Labs inference proxy (planned: `POST /api/plugin/inference`), and
    returns the Venice-routed completion.

    Endpoint design recorded in
    `memory/research/2026-05-15-self-learning-design.md`.
    """

    name = "venice-x402"

    def __init__(
        self,
        inference_fn: Callable[[str], str],
        *,
        account_id: str,
    ) -> None:
        self._inference_fn = inference_fn
        self._account_id = account_id

    def summarize(
        self,
        pattern_kind: str,
        events: list[dict[str, Any]],
        hints: dict[str, Any],
    ) -> tuple[str, str | None]:
        # Sibyl-routed path (#14, 2026-06-30): the prompt is relayed through
        # Sibyl Labs' own inference proxy, so the privacy contract is that
        # "only the prompt summary leaves the device, never the underlying
        # memory content." Redact event payloads to metadata only
        # (keys / counts / timestamps) before assembling the prompt; raw
        # journal content must not reach the Sibyl-routed prompt.
        prompt = _build_summarization_prompt(pattern_kind, events, hints, redact=True)
        try:
            body = self._inference_fn(prompt)
        except Exception as e:  # pragma: no cover
            fallback = LocalDeterministicSummarizer()
            body, title = fallback.summarize(pattern_kind, events, hints)
            return body + f"\n\n---\n_Note: Venice/x402 call failed ({e}). Using local fallback._", title
        title = hints.get("title") or _slug_to_title(hints.get("slug", pattern_kind))
        return body, title


# ----------------------------------------------------------------------
# Learner: orchestrates detection + summarization + persistence
# ----------------------------------------------------------------------

class Learner:
    """Periodic learning loop. Reads journal, writes skill proposals.

    Args:
        storage: the live Storage instance
        tenant_id: which tenant's journal to scan
        summarizer: pluggable summarizer (defaults to local-deterministic)
        min_pattern_hits: minimum matched events to surface a pattern
        max_proposals_per_run: cap to avoid swamping the review queue
        cap_gate: optional CapGate. When provided, accept_proposal calls
            the gate before writing the reference_documents row (T1-3 fix).
            When None, no cap check is performed: exposed for advanced
            callers who construct Learner directly and own their own
            enforcement.
    """

    def __init__(
        self,
        storage: Storage,
        *,
        tenant_id: str = DEFAULT_TENANT,
        summarizer: Summarizer | None = None,
        min_pattern_hits: int = 3,
        max_proposals_per_run: int = 20,
        cap_gate: Any = None,
    ) -> None:
        self._storage = storage
        self._tenant_id = tenant_id
        self._summarizer = summarizer or LocalDeterministicSummarizer()
        self._min_hits = max(2, min_pattern_hits)
        self._max_per_run = max(1, max_proposals_per_run)
        self._cap_gate = cap_gate

    # ------------------------------------------------------------------
    # Public entry points
    # ------------------------------------------------------------------
    def run(self, *, since: str | None = None, exclude_kinds: Iterable[str] = (),
            unmuted: dict[str, Any] | None = None,
            signals: dict[str, Any] | None = None) -> LearningRunReport:
        """Scan journal events since the last watermark and propose skills.

        ``exclude_kinds``: pattern kinds the person muted (no proposal of that
        kind is created). A slug is never re-proposed while it is pending or
        accepted, for ``REJECT_COOL_OFF_DAYS`` after a rejection, and at all
        once rejected ``REJECT_MUTE_COUNT`` times (``unmuted`` maps a slug to
        the epoch seconds of a ``sibyl skills proposals unmute``; only
        rejections after it count).

        ``signals`` (R2): the loaded ``signals.json`` snapshot
        (``lifecycle.signals.load``); when given, the ``tool_sequence`` and
        ``correction_loop`` detectors run too, even when the journal has
        nothing new."""
        run_id = new_id()
        started_at = _utc_now_iso()

        # Hardening #15 (super-patch 2026-07-05): make sure the rowid-watermark
        # column exists before we read/write it (idempotent, one-time ALTER on a
        # pre-super-patch DB).
        self._ensure_rowid_watermark_column()

        # Resolve watermark. Default path cursors on the monotonic journal
        # ``rowid`` (Hardening #15) so concurrent / same-timestamp / backdated
        # events are never skipped by a strict ``ts >`` comparison. An explicit
        # ``since`` (a timestamp) stays an escape hatch to re-scan from a point in
        # time; when supplied it filters by ts instead of the rowid watermark.
        after_rowid = None if since else self._last_watermark_rowid()
        events = self._load_events(since_ts=since, after_rowid=after_rowid)
        scanned = len(events)

        # Skip detection entirely if there's nothing new
        proposal_ids: list[str] = []
        signal_candidates: list[_Candidate] = []
        if signals:
            import time as _time
            _now = _time.time()
            signal_candidates.extend(_detect_tool_sequence(signals, _now, min_hits=self._min_hits))
            signal_candidates.extend(_detect_correction_loop(signals, self._storage, self._tenant_id, _now))
        if scanned == 0 and not signal_candidates:
            self._log_run(
                run_id=run_id,
                started_at=started_at,
                completed_at=_utc_now_iso(),
                events_scanned=0,
                proposals_made=0,
                cursor_after_ts=since,
                cursor_after_rowid=after_rowid,
                notes="no new events since last run",
            )
            return LearningRunReport(
                run_id=run_id,
                events_scanned=0,
                proposals_made=0,
                proposal_ids=[],
                started_at=started_at,
                completed_at=_utc_now_iso(),
                summarizer=self._summarizer.name,
            )

        # Run detectors, accumulate candidate proposals
        candidates: list[_Candidate] = []
        if events:
            candidates.extend(_detect_repeated_actions(events, min_hits=self._min_hits))
            candidates.extend(_detect_structural_similarity(events, min_hits=self._min_hits))
            candidates.extend(_detect_co_occurrence(events, min_hits=self._min_hits))
            # temporal_routine: light-touch detector, deliberately last
            candidates.extend(_detect_temporal_routine(events, min_hits=self._min_hits))
        candidates.extend(signal_candidates)

        # Deduplicate by slug: keep the highest-confidence candidate per slug
        deduped: dict[str, _Candidate] = {}
        for c in candidates:
            existing = deduped.get(c.slug)
            if existing is None or c.confidence > existing.confidence:
                deduped[c.slug] = c

        # Cap, sort by confidence
        ranked = sorted(deduped.values(), key=lambda c: -c.confidence)[: self._max_per_run]

        # Skip ones that already exist as pending proposals (same tenant, same slug),
        # accepted ones, rejected ones inside the cool-off, twice-rejected ones
        # (until unmuted) and muted kinds.
        existing_slugs = self._pending_slugs() | self._blocked_slugs(unmuted or {})
        excluded = set(exclude_kinds or ())
        ranked = [c for c in ranked if c.slug not in existing_slugs and c.kind not in excluded]

        # Persist
        signal_keys: list[str] = []
        for c in ranked:
            body, title = self._summarizer.summarize(c.kind, c.events, c.hints)
            pid = self._insert_proposal(c, body=body, title=title)
            proposal_ids.append(pid)
            signal_keys.extend(c.signal_keys)

        # Watermark: advance on the monotonic rowid so no same-ts row is ever
        # skipped next run (Hardening #15). Keep the max ts too, for readable logs.
        max_rowid = max([(ev.get("rowid") or 0) for ev in events] or [0])
        cursor_after_rowid = max(max_rowid, after_rowid or 0) if (events or after_rowid) else None
        cursor_after_ts = (max((ev.get("ts") or "") for ev in events) or None) if events else since

        self._log_run(
            run_id=run_id,
            started_at=started_at,
            completed_at=_utc_now_iso(),
            events_scanned=scanned,
            proposals_made=len(proposal_ids),
            cursor_after_ts=cursor_after_ts,
            cursor_after_rowid=cursor_after_rowid,
            notes=None,
        )

        return LearningRunReport(
            run_id=run_id,
            events_scanned=scanned,
            proposals_made=len(proposal_ids),
            proposal_ids=proposal_ids,
            started_at=started_at,
            completed_at=_utc_now_iso(),
            summarizer=self._summarizer.name,
            signal_keys=signal_keys,
        )

    def list_proposals(
        self,
        *,
        status: str = "pending",
        limit: int = 50,
    ) -> list[SkillProposal]:
        with self._storage.connection() as conn:
            rows = conn.execute(
                "SELECT * FROM skill_proposals "
                "WHERE tenant_id = ? AND status = ? "
                "ORDER BY confidence DESC, created_at DESC LIMIT ?",
                (self._tenant_id, status, limit),
            ).fetchall()
        return [_row_to_proposal(r) for r in rows]

    def get_proposal(self, proposal_id: str) -> SkillProposal:
        with self._storage.connection() as conn:
            row = conn.execute(
                "SELECT * FROM skill_proposals WHERE id = ? AND tenant_id = ?",
                (proposal_id, self._tenant_id),
            ).fetchone()
        if row is None:
            raise NotFoundError(f"skill_proposal {proposal_id} not found")
        return _row_to_proposal(row)

    def accept_proposal(
        self,
        proposal_id: str,
        *,
        note: str | None = None,
    ) -> dict[str, Any]:
        """Accept a proposal. Writes a reference_documents row keyed
        `skill/<slug>` and marks the proposal accepted."""
        proposal = self.get_proposal(proposal_id)
        if proposal.status != "pending":
            raise ValidationError(
                f"proposal {proposal_id} is {proposal.status}, cannot accept",
                recovery="Only pending proposals can be accepted. Use list_proposals(status='pending').",
            )
        doc_key = f"skill/{proposal.proposed_slug}"
        metadata = {
            "source": "sibyl-memory-client/learning",
            "pattern_kind": proposal.pattern_kind,
            "summarizer": proposal.summarizer,
            "confidence": proposal.confidence,
            "evidence_count": len(proposal.evidence),
            "title": proposal.proposed_title,
        }
        metadata_json = dumps(metadata)
        # T1-3 fix: gate the reference_documents insert through the cap
        # check. Free user at 1.9MB could previously accept skill proposals
        # (often kilobytes of body) to keep writing past the 5 MB cap.
        # When cap_gate is None (direct-Learner instantiation), no check.
        if self._cap_gate is not None:
            # CAP-7 (2026-06-25 pre-launch audit): the estimate omitted the
            # metadata JSON and the FTS5 index overhead. reference_documents is
            # FTS5-indexed, so the body is effectively stored twice-over (base
            # row + tokenized index). Count the body + metadata + key, then add a
            # ~1x body FTS overhead factor plus base row overhead, so the cap
            # estimate is not a systematic under-count that lets accept_proposal
            # squeak past the cap.
            body_len = len(proposal.proposed_body or "")
            fts_overhead = body_len  # FTS5 index roughly mirrors the body size
            body_size = body_len + len(metadata_json) + len(doc_key) + fts_overhead + 250
            self._cap_gate.check(proposed_delta_bytes=body_size)
        with self._storage.transaction() as conn:
            conn.execute(
                "INSERT INTO reference_documents (tenant_id, doc_key, body, metadata) "
                "VALUES (?, ?, ?, ?) "
                "ON CONFLICT(tenant_id, doc_key) DO UPDATE SET "
                "body = excluded.body, metadata = excluded.metadata, "
                "updated_at = strftime('%Y-%m-%dT%H:%M:%fZ', 'now')",
                (
                    self._tenant_id,
                    doc_key,
                    proposal.proposed_body,
                    metadata_json,
                ),
            )
            # Hardening #8 (super-patch 2026-07-05): in-transaction CAP-2 recheck.
            # The pre-txn check() above gates on a byte ESTIMATE; this reads the
            # TRUE logical footprint with the INSERT already staged (write lock
            # held) and rejects — rolling back the staged rows — if it tips the
            # DB over the cap. check_total_local is LOCAL-ONLY (no network) so it
            # is safe to call under the write lock. Skipped for cap gates that do
            # not implement it (advanced/direct callers, e.g. estimate-only test
            # doubles); the production CapGate always does.
            if self._cap_gate is not None:
                check_total_local = getattr(self._cap_gate, "check_total_local", None)
                if callable(check_total_local):
                    check_total_local(self._storage.logical_size_bytes(conn))
            # Hardening #8: guard the state transition with AND status = 'pending'
            # so a concurrent double-accept (two callers that both passed the
            # pre-txn status check) cannot both commit. rowcount == 0 means the
            # proposal was already reviewed under us — raise so this txn (and its
            # staged reference_documents write) rolls back.
            cur = conn.execute(
                "UPDATE skill_proposals "
                "SET status = 'accepted', reviewed_at = strftime('%Y-%m-%dT%H:%M:%fZ', 'now'), "
                "review_note = ?, accepted_doc_key = ? "
                "WHERE id = ? AND tenant_id = ? AND status = 'pending'",
                (note, doc_key, proposal_id, self._tenant_id),
            )
            if cur.rowcount == 0:
                raise ValidationError(
                    f"proposal {proposal_id} is no longer pending, cannot accept",
                    recovery="It was reviewed concurrently. Re-list with list_proposals(status='pending').",
                )
        return {"accepted": True, "doc_key": doc_key, "proposal_id": proposal_id}

    def reject_proposal(
        self,
        proposal_id: str,
        *,
        note: str | None = None,
    ) -> dict[str, Any]:
        proposal = self.get_proposal(proposal_id)
        if proposal.status != "pending":
            raise ValidationError(
                f"proposal {proposal_id} is {proposal.status}, cannot reject",
                recovery="Only pending proposals can be rejected.",
            )
        with self._storage.transaction() as conn:
            # Hardening #8: same status='pending' guard as accept_proposal so a
            # concurrent reject/accept race cannot clobber an already-reviewed row.
            cur = conn.execute(
                "UPDATE skill_proposals "
                "SET status = 'rejected', reviewed_at = strftime('%Y-%m-%dT%H:%M:%fZ', 'now'), "
                "review_note = ? "
                "WHERE id = ? AND tenant_id = ? AND status = 'pending'",
                (note, proposal_id, self._tenant_id),
            )
            if cur.rowcount == 0:
                raise ValidationError(
                    f"proposal {proposal_id} is no longer pending, cannot reject",
                    recovery="It was reviewed concurrently. Re-list with list_proposals(status='pending').",
                )
        return {"rejected": True, "proposal_id": proposal_id}

    # ------------------------------------------------------------------
    # Internal
    # ------------------------------------------------------------------
    def _ensure_rowid_watermark_column(self) -> None:
        """Idempotently add ``learning_runs.cursor_after_rowid`` (Hardening #15).

        The rowid watermark needs a column the shipped v2 schema does not carry.
        Adding it here (rather than editing schema.sql) keeps the whole fix inside
        the learner: on the first run against an existing DB the column is created;
        every later run short-circuits on the PRAGMA check. Guarded so a concurrent
        process racing the same ALTER is harmless.
        """
        with self._storage.connection() as conn:
            cols = {r[1] for r in conn.execute(
                "PRAGMA table_info(learning_runs)").fetchall()}
        if "cursor_after_rowid" in cols:
            return
        with self._storage.transaction() as conn:
            cols = {r[1] for r in conn.execute(
                "PRAGMA table_info(learning_runs)").fetchall()}
            if "cursor_after_rowid" not in cols:
                try:
                    conn.execute(
                        "ALTER TABLE learning_runs ADD COLUMN cursor_after_rowid INTEGER")
                except sqlite3.OperationalError:
                    # Another process added it between our check and the ALTER.
                    pass

    def _last_watermark_rowid(self) -> int | None:
        with self._storage.connection() as conn:
            try:
                row = conn.execute(
                    "SELECT cursor_after_rowid FROM learning_runs "
                    "WHERE tenant_id = ? AND completed_at IS NOT NULL "
                    "AND cursor_after_rowid IS NOT NULL "
                    "ORDER BY started_at DESC LIMIT 1",
                    (self._tenant_id,),
                ).fetchone()
            except sqlite3.OperationalError:
                # Column not yet present (pre-super-patch DB, before ensure ran).
                return None
        if row is None or row["cursor_after_rowid"] is None:
            return None
        return int(row["cursor_after_rowid"])

    def _load_events(
        self,
        *,
        since_ts: str | None = None,
        after_rowid: int | None = None,
    ) -> list[dict[str, Any]]:
        sql = (
            "SELECT rowid AS event_rowid, id, ts, evaluated, acted, forward, extra "
            "FROM journal_events WHERE tenant_id = ?"
        )
        params: list[Any] = [self._tenant_id]
        if since_ts:
            sql += " AND ts > ?"
            params.append(since_ts)
        if after_rowid is not None:
            sql += " AND rowid > ?"
            params.append(after_rowid)
        # F6 + Hardening #15: order by the monotonic rowid (insertion order) so
        # the watermark advances without ever skipping a same-ts row, and a
        # backlog over the cap drains oldest-first across subsequent runs.
        sql += " ORDER BY rowid ASC LIMIT ?"
        params.append(_MAX_EVENTS_PER_RUN)
        with self._storage.connection() as conn:
            rows = conn.execute(sql, params).fetchall()
        if len(rows) >= _MAX_EVENTS_PER_RUN:
            logger.warning(
                "Sibyl learner scan hit the per-run cap (%d events); a large "
                "journal backlog will drain across multiple runs.",
                _MAX_EVENTS_PER_RUN,
            )
        return [
            {
                "rowid": r["event_rowid"],
                "id": r["id"],
                "ts": r["ts"],
                "evaluated": loads(r["evaluated"]),
                "acted": loads(r["acted"]),
                "forward": loads(r["forward"]),
                "extra": loads(r["extra"]),
            }
            for r in rows
        ]

    def _pending_slugs(self) -> set[str]:
        with self._storage.connection() as conn:
            rows = conn.execute(
                "SELECT proposed_slug FROM skill_proposals "
                "WHERE tenant_id = ? AND status = 'pending'",
                (self._tenant_id,),
            ).fetchall()
        return {r["proposed_slug"] for r in rows}

    def _blocked_slugs(self, unmuted: dict[str, Any], *, now: float | None = None) -> set[str]:
        """Slugs not to propose again: accepted (any time), rejected within the
        cool-off, rejected ``REJECT_MUTE_COUNT`` or more times after the last
        unmute."""
        import time as _time
        from datetime import datetime, timezone
        now = _time.time() if now is None else now
        with self._storage.connection() as conn:
            rows = conn.execute(
                "SELECT proposed_slug, status, reviewed_at FROM skill_proposals "
                "WHERE tenant_id = ? AND status IN ('accepted', 'rejected')",
                (self._tenant_id,),
            ).fetchall()
        out: set[str] = set()
        rejections: dict[str, int] = defaultdict(int)
        for r in rows:
            slug = r["proposed_slug"]
            if r["status"] == "accepted":
                out.add(slug)
                continue
            try:
                when = datetime.fromisoformat(str(r["reviewed_at"]).replace("Z", "+00:00"))
                if when.tzinfo is None:
                    when = when.replace(tzinfo=timezone.utc)
                ts = when.timestamp()
            except (TypeError, ValueError):
                ts = now          # unknown review time: treat as just now (cools off)
            un = unmuted.get(slug)
            if isinstance(un, (int, float)) and not isinstance(un, bool) and ts <= un:
                continue          # rejected before the person unmuted it
            if now - ts < REJECT_COOL_OFF_DAYS * 86400:
                out.add(slug)
            rejections[slug] += 1
        out.update(s for s, n in rejections.items() if n >= REJECT_MUTE_COUNT)
        return out

    def _insert_proposal(
        self,
        candidate: "_Candidate",
        *,
        body: str,
        title: str | None,
    ) -> str:
        pid = new_id()
        with self._storage.transaction() as conn:
            conn.execute(
                "INSERT INTO skill_proposals "
                "(id, tenant_id, pattern_kind, proposed_slug, proposed_title, "
                " proposed_body, evidence, confidence, summarizer) "
                "VALUES (?, ?, ?, ?, ?, ?, ?, ?, ?)",
                (
                    pid,
                    self._tenant_id,
                    candidate.kind,
                    candidate.slug,
                    title,
                    body,
                    dumps([
                        {"event_id": ev.get("id"), "ts": ev.get("ts"),
                         "snippet": ev.get("snippet") or _short_event_snippet(ev)}
                        # the most recent 20 (the relevance filter reads recency)
                        for ev in candidate.events[-20:]
                    ]),
                    candidate.confidence,
                    self._summarizer.name,
                ),
            )
        return pid

    def _log_run(
        self,
        *,
        run_id: str,
        started_at: str,
        completed_at: str,
        events_scanned: int,
        proposals_made: int,
        cursor_after_ts: str | None,
        cursor_after_rowid: int | None = None,
        notes: str | None,
    ) -> None:
        with self._storage.transaction() as conn:
            conn.execute(
                "INSERT INTO learning_runs "
                "(id, tenant_id, started_at, completed_at, summarizer, "
                " events_scanned, proposals_made, cursor_after_ts, "
                " cursor_after_rowid, notes) "
                "VALUES (?, ?, ?, ?, ?, ?, ?, ?, ?, ?)",
                (
                    run_id,
                    self._tenant_id,
                    started_at,
                    completed_at,
                    self._summarizer.name,
                    events_scanned,
                    proposals_made,
                    cursor_after_ts,
                    cursor_after_rowid,
                    notes,
                ),
            )


# ======================================================================
# Pattern detectors (deterministic, local-only)
# ======================================================================

@dataclass
class _Candidate:
    kind: str
    slug: str
    confidence: float
    events: list[dict[str, Any]]
    hints: dict[str, Any]
    signal_keys: list[str] = field(default_factory=list)


def _detect_repeated_actions(
    events: list[dict[str, Any]],
    *,
    min_hits: int,
) -> list[_Candidate]:
    """Cluster events by an abstracted action signature; surface clusters
    that occur >= min_hits times."""
    by_sig: dict[str, list[dict[str, Any]]] = defaultdict(list)
    for ev in events:
        acted = ev.get("acted")
        if acted is None:
            continue
        sig = _action_signature(acted)
        if not sig:
            continue
        by_sig[sig].append(ev)

    out: list[_Candidate] = []
    for sig, group in by_sig.items():
        if len(group) < min_hits:
            continue
        slug = _safe_slug("repeat-" + sig)
        # confidence scales with hit count, capped at 0.95
        confidence = min(0.95, 0.4 + 0.05 * len(group))
        out.append(_Candidate(
            kind="repeated_action",
            slug=slug,
            confidence=confidence,
            events=group,
            hints={"action_signature": sig, "slug": slug, "hits": len(group)},
        ))
    return out


def _detect_structural_similarity(
    events: list[dict[str, Any]],
    *,
    min_hits: int,
) -> list[_Candidate]:
    """Group events that share a stable set of input/output keys."""
    by_keys: dict[tuple[str, ...], list[dict[str, Any]]] = defaultdict(list)
    for ev in events:
        evaluated = ev.get("evaluated")
        if not isinstance(evaluated, dict):
            continue
        keyset = tuple(sorted(evaluated.keys()))
        if not keyset:
            continue
        by_keys[keyset].append(ev)

    out: list[_Candidate] = []
    for keyset, group in by_keys.items():
        if len(group) < min_hits:
            continue
        slug = _safe_slug("shape-" + "-".join(keyset[:4]))
        confidence = min(0.85, 0.3 + 0.04 * len(group))
        out.append(_Candidate(
            kind="structural_similarity",
            slug=slug,
            confidence=confidence,
            events=group,
            hints={"shared_keys": list(keyset), "slug": slug, "hits": len(group)},
        ))
    return out


def _detect_co_occurrence(
    events: list[dict[str, Any]],
    *,
    min_hits: int,
) -> list[_Candidate]:
    """Find pairs of distinct tokens (entity names / action verbs) that
    consistently appear together in the same journal entry."""
    pair_counts: Counter[tuple[str, str]] = Counter()
    pair_events: dict[tuple[str, str], list[dict[str, Any]]] = defaultdict(list)
    for ev in events:
        toks = _extract_tokens(ev)
        if len(toks) < 2:
            continue
        # R13: bounded by _MAX_TOKENS_PER_EVENT, so this double loop is at most
        # C(64, 2) = 2016 pairs per event rather than O(len(body)²).
        toks_sorted = sorted(set(toks))
        # All 2-combos
        for i in range(len(toks_sorted)):
            for j in range(i + 1, len(toks_sorted)):
                pair = (toks_sorted[i], toks_sorted[j])
                if pair not in pair_counts and len(pair_counts) >= _MAX_TRACKED_PAIRS:
                    # R13: stop tracking NEW pairs once the ceiling is hit; keep
                    # counting pairs already seen so established co-occurrences
                    # still surface. Bounds total memory across a large run.
                    continue
                pair_counts[pair] += 1
                pair_events[pair].append(ev)

    out: list[_Candidate] = []
    for pair, count in pair_counts.items():
        if count < min_hits:
            continue
        slug = _safe_slug(f"pair-{pair[0]}-{pair[1]}")
        confidence = min(0.80, 0.25 + 0.04 * count)
        out.append(_Candidate(
            kind="co_occurrence",
            slug=slug,
            confidence=confidence,
            events=pair_events[pair],
            hints={"pair": list(pair), "slug": slug, "hits": count},
        ))
    return out


def _detect_temporal_routine(
    events: list[dict[str, Any]],
    *,
    min_hits: int,
) -> list[_Candidate]:
    """Crude cadence detector: if same-signature events recur with low
    variance in time-between-events, surface as a temporal routine."""
    by_sig: dict[str, list[dict[str, Any]]] = defaultdict(list)
    for ev in events:
        acted = ev.get("acted")
        if acted is None:
            continue
        sig = _action_signature(acted)
        if sig:
            by_sig[sig].append(ev)

    out: list[_Candidate] = []
    for sig, group in by_sig.items():
        if len(group) < min_hits:
            continue
        gaps_min = _intervals_minutes([ev.get("ts") for ev in group])
        if not gaps_min:
            continue
        mean = sum(gaps_min) / len(gaps_min)
        if mean <= 0:
            continue
        # Coefficient of variation: lower = more regular
        var = sum((g - mean) ** 2 for g in gaps_min) / len(gaps_min)
        cov = (var ** 0.5) / mean
        if cov >= 0.6:
            continue  # too irregular to call a routine
        slug = _safe_slug(f"routine-{sig}")
        # Routine confidence rewards regularity
        confidence = min(0.90, 0.5 + (0.5 * (1 - cov)))
        out.append(_Candidate(
            kind="temporal_routine",
            slug=slug,
            confidence=confidence,
            events=group,
            hints={
                "action_signature": sig,
                "slug": slug,
                "hits": len(group),
                "cadence_minutes": round(mean, 1),
                "cov": round(cov, 3),
            },
        ))
    return out


# ======================================================================
# Skill-signal detectors (R2, spec plugin-paid-tier-r2 1.4): they read the
# signals.json snapshot, never the journal, and return candidates with
# SYNTHETIC evidence (event_id null, a timestamp and a one-line snippet), so
# the rest of the pipeline (slug dedupe, blocked slugs, insert, relevance,
# accept / reject) is unchanged.
# ======================================================================

SEQ_ONE_SESSION = 3
SEQ_ACROSS_SESSIONS = 5
SEQ_MIN_SESSIONS = 2
SEQ_WINDOW_DAYS = 7
LOOP_MIN_REWRITES = 3
LOOP_MIN_SPAN_SECONDS = 10 * 60
LOOP_RECREATE_SECONDS = 24 * 3600
ENTITY_RESOLVE_LIMIT = 5000
REMOVED_ENTITY = "an entity that has since been removed"

# The agent's retrieval rhythm, not a skill: a sequence made only of these is
# never proposed.
_READ_ONLY_TOOLS = frozenset({
    "memory_search", "memory_recall", "memory_list", "memory_get_state",
    "sibyl_search", "sibyl_recall", "sibyl_list", "sibyl_prefetch", "prefetch",
})


def _bare_tool(name: str) -> str:
    """``mcp__<server>__<tool>`` -> ``<tool>``."""
    if name.startswith("mcp__"):
        parts = name.split("__")
        if len(parts) >= 3:
            return parts[-1]
    return name


def _slug_tool(name: str) -> str:
    """``mcp__x__y`` -> ``x-y``; any other name safe-slugged."""
    if name.startswith("mcp__"):
        parts = [p for p in name.split("__")[1:] if p]
        return _safe_slug("-".join(parts))
    return _safe_slug(name)


def _iso_ts(ts: float) -> str:
    from datetime import datetime, timezone
    return datetime.fromtimestamp(float(ts), timezone.utc).strftime("%Y-%m-%dT%H:%M:%S.000Z")


def _contains(seq: list[Any], sub: list[Any]) -> bool:
    n = len(sub)
    return any(seq[i:i + n] == sub for i in range(len(seq) - n + 1))


def _detect_tool_sequence(signals: dict[str, Any], now: float, *, min_hits: int = SEQ_ONE_SESSION
                          ) -> list[_Candidate]:
    """``tool_sequence``: an n-gram (3..5 tool calls) seen ``min_hits`` (3)
    times in one session, or 5 times in the last 7 days across at least 2
    sessions. Excluded: all names identical; only memory read tools. The
    longest gram wins over a contained gram seen no more often, and the
    windows of one loop (A B C A B C ...) are one pattern."""
    import time as _time
    ngrams = (signals or {}).get("ngrams") or {}
    horizon = now - SEQ_WINDOW_DAYS * 86400
    first_day = _time.strftime("%Y-%m-%d", _time.gmtime(now - (SEQ_WINDOW_DAYS - 1) * 86400))
    q: list[dict[str, Any]] = []
    for key, e in ngrams.items():
        tools = list(e.get("tools") or [])
        shapes = list(e.get("shapes") or [])
        if len(tools) < 3 or len(set(tools)) == 1:
            continue
        if all(_bare_tool(t) in _READ_ONLY_TOOLS for t in tools):
            continue
        sessions = [s for s in (e.get("sessions") or []) if s[2] >= horizon]
        best = max((int(s[1]) for s in sessions), default=0)
        recent = sum(int(c) for d, c in (e.get("days") or {}).items() if d >= first_day)
        if not (best >= min_hits or (recent >= SEQ_ACROSS_SESSIONS and len(sessions) >= SEQ_MIN_SESSIONS)):
            continue
        q.append({"key": key, "e": e, "tools": tools, "shapes": shapes,
                  "toks": list(zip(tools, shapes)), "count": max(recent, best),
                  "sessions": len(sessions)})
    # Longest wins: a contained gram seen no more often than the longer one is
    # the same occurrences.
    q = [c for c in q if not any(len(o["toks"]) > len(c["toks"]) and o["count"] >= c["count"]
                                 and _contains(o["toks"], c["toks"]) for o in q)]
    # One loop, one pattern: a window of a kept sequence repeated (A B C A B C)
    # seen no more often is not a second pattern.
    kept: list[dict[str, Any]] = []
    for c in sorted(q, key=lambda c: (-c["count"], len(c["toks"]), c["key"])):
        if any(k is not c and c["count"] <= k["count"]
               and _contains(k["toks"] * (len(c["toks"]) // len(k["toks"]) + 2), c["toks"])
               for k in kept):
            continue
        kept.append(c)
    out: list[_Candidate] = []
    for c in kept:
        tools, shapes = c["tools"], c["shapes"]
        slug = _safe_slug("seq-" + "-".join(_slug_tool(t) for t in tools[:3]))
        if any(o is not c and o["tools"] == tools and o["shapes"] != shapes for o in kept):
            import hashlib as _h
            slug = _safe_slug(slug + "-" + _h.sha256("|".join(shapes).encode()).hexdigest()[:4])
        conf = 0.60 + 0.05 * (c["count"] - 3) + (0.05 if c["sessions"] >= 2 else 0.0)
        conf = round(min(0.85, max(0.60, conf)), 2)
        arrow = " -> ".join(tools)
        e = c["e"]
        stamps = sorted(e.get("ts") or [])[-20:]
        events = [{"id": None, "ts": _iso_ts(t), "snippet": arrow, "acted": arrow} for t in stamps]
        title = "Recurring sequence: " + ", ".join(tools)
        out.append(_Candidate(
            kind="tool_sequence", slug=slug, confidence=conf, events=events,
            hints={"tool_names": tools, "shapes": shapes, "hits": c["count"],
                   "sessions": c["sessions"], "first_seen": _iso_ts(e.get("first") or now),
                   "last_seen": _iso_ts(e.get("last") or now), "slug": slug, "title": title},
            signal_keys=[c["key"]],
        ))
    return out


def _resolve_entities(storage: Any, tenant_id: str, hashes: set[str]) -> dict[str, tuple[str, str]]:
    """Hash -> (category, name) for the entities that exist now (one bounded
    SELECT; the names never went into signals.json)."""
    if not hashes:
        return {}
    from .lifecycle.signals import entity_hash
    out: dict[str, tuple[str, str]] = {}
    try:
        with storage.connection() as conn:
            rows = conn.execute("SELECT category, name FROM entities WHERE tenant_id = ? LIMIT ?",
                                (tenant_id, ENTITY_RESOLVE_LIMIT)).fetchall()
    except Exception:
        return {}
    for r in rows:
        h = entity_hash(tenant_id, r[0], r[1])
        if h in hashes:
            out[h] = (r[0], r[1])
    return out


def _detect_correction_loop(signals: dict[str, Any], storage: Any, tenant_id: str, now: float
                            ) -> list[_Candidate]:
    """``correction_loop``: one entity written 3 or more times in one session
    spanning at least 10 minutes (a shorter burst is the save procedure at
    work), or deleted / archived and written again within 24 hours."""
    from .lifecycle.signals import OP_NAMES
    writes = (signals or {}).get("entity_writes") or {}
    hits: dict[str, dict[str, Any]] = {}
    for h, rows in writes.items():
        rows = sorted(rows, key=lambda r: r[1])
        sets = [r for r in rows if r[0] == "s"]
        by_session: dict[str, list[float]] = defaultdict(list)
        for r in sets:
            by_session[r[2]].append(r[1])
        loop_session = None
        for s8, ts in by_session.items():
            if len(ts) >= LOOP_MIN_REWRITES and max(ts) - min(ts) >= LOOP_MIN_SPAN_SECONDS:
                if loop_session is None or len(ts) > len(by_session[loop_session]):
                    loop_session = s8
        recreated = any(r[0] in ("d", "a") and any(0 < w[1] - r[1] <= LOOP_RECREATE_SECONDS for w in sets)
                        for r in rows)
        if loop_session is None and not recreated:
            continue
        hits[h] = {"rows": rows, "sets": sets, "loop_session": loop_session,
                   "by_session": by_session, "recreated": recreated,
                   "sessions": len({r[2] for r in rows})}
    if not hits:
        return []
    names = _resolve_entities(storage, tenant_id, set(hits))
    out: list[_Candidate] = []
    for h, info in hits.items():
        resolved = names.get(h)
        label = f"{resolved[0]}/{resolved[1]}" if resolved else None
        slug = _safe_slug(f"fix-{resolved[0]}-{resolved[1]}") if resolved else f"fix-{h[:8]}"
        conf = 0.75 if info["sessions"] >= 2 else 0.65
        conf = round(min(0.85, conf), 2)
        events = []
        for op, ts, _s8 in info["rows"][-20:]:
            snip = f"{OP_NAMES.get(op, 'set_entity')} {label}" if label else \
                f"{OP_NAMES.get(op, 'set_entity')} (removed entity)"
            events.append({"id": None, "ts": _iso_ts(ts), "snippet": snip, "acted": snip})
        loop = info["loop_session"]
        in_loop = sorted(info["by_session"][loop]) if loop is not None else []
        title = f"Recording {label}" if label else "Recording a removed entity"
        out.append(_Candidate(
            kind="correction_loop", slug=slug, confidence=conf, events=events,
            hints={"entity": label or REMOVED_ENTITY, "rewrites": len(info["sets"]),
                   "rewrites_in_one_session": len(in_loop),
                   "loop_day": _iso_ts(in_loop[0])[:10] if in_loop else None,
                   "deleted_then_recreated": bool(info["recreated"]), "sessions": info["sessions"],
                   "first_seen": _iso_ts(info["rows"][0][1]), "last_seen": _iso_ts(info["rows"][-1][1]),
                   "slug": slug, "title": title},
            signal_keys=[h],
        ))
    return out


def _signal_body(kind: str, events: list[dict[str, Any]], hints: dict[str, Any], title: str) -> str:
    """The local-deterministic bodies of the two signal kinds (copy DRAFT,
    JANUS reviews before 0.10 ships)."""
    lines = [f"# {title}", ""]
    n = len(events)
    if kind == "tool_sequence":
        tools = list(hints.get("tool_names") or [])
        arrow = " -> ".join(tools)
        sessions = int(hints.get("sessions") or 1)
        where = "in one session" if sessions <= 1 else f"across {sessions} sessions"
        since = str(hints.get("first_seen") or "?")[:10]
        lines += [f"_Auto-detected from {n} recorded occurrences of one tool sequence._", "",
                  "## Pattern", "",
                  f"Recurring tool sequence: `{arrow}`, seen {hints.get('hits', n)} times {where} "
                  f"since {since}. The arguments had the same shape each time.", ""]
    else:
        entity = hints.get("entity") or REMOVED_ENTITY
        shown = f"`{entity}`" if entity != REMOVED_ENTITY else entity
        lead = "The entity " + shown if entity != REMOVED_ENTITY else "An entity (" + entity + ")"
        parts = []
        k = int(hints.get("rewrites_in_one_session") or 0)
        total = int(hints.get("rewrites") or 0)
        if k:
            more = total - k
            parts.append(f"{lead} was rewritten {k} times in one session on {hints.get('loop_day')}"
                         + (f", and {more} more {'time' if more == 1 else 'times'} since." if more > 0 else "."))
        if hints.get("deleted_then_recreated"):
            parts.append(("It" if parts else lead) + " was removed and written again within a day.")
        lines += [f"_Auto-detected from {n} recorded writes to one entity._", "", "## Pattern", "",
                  " ".join(parts) + " A short checklist for how this entity is recorded would save "
                  "the rewrites.", ""]
    lines += ["## Evidence", ""]
    for ev in events[-5:]:
        lines.append(f"- `{ev.get('ts') or '?'}`: {ev.get('snippet') or _short_event_snippet(ev)}")
    if n > 5:
        lines.append(f"- _and {n - 5} earlier occurrences_")
    lines += ["", "## Suggested skill", ""]
    if kind == "tool_sequence":
        for i, t in enumerate(hints.get("tool_names") or [], 1):
            lines.append(f"{i}. {t}")
        lines += ["", "Fill in what each step checks; the sequence is the skeleton, you know the intent."]
    else:
        lines += ["1. What to check before writing this entity.",
                  "2. What the entry must contain.",
                  "3. When to archive it instead of rewriting it."]
    return "\n".join(lines)


# ======================================================================
# Helpers
# ======================================================================

def _action_signature(acted: Any) -> str:
    """Reduce an `acted` payload to a stable signature for clustering."""
    if isinstance(acted, list):
        # Use the first verb / phrase, lowercased + truncated
        if not acted:
            return ""
        first = acted[0]
        if isinstance(first, str):
            return _normalize_phrase(first)
        if isinstance(first, dict):
            kind = first.get("kind") or first.get("action") or first.get("type")
            if isinstance(kind, str):
                return _normalize_phrase(kind)
        return ""
    if isinstance(acted, dict):
        kind = acted.get("kind") or acted.get("action") or acted.get("type")
        if isinstance(kind, str):
            return _normalize_phrase(kind)
        return ""
    if isinstance(acted, str):
        return _normalize_phrase(acted)
    return ""


_WORD_RE = re.compile(r"[a-z0-9][a-z0-9_-]+")


def _normalize_phrase(text: str) -> str:
    """Lowercase, strip non-alpha, collapse to first 3 tokens."""
    text = text.lower().strip()
    tokens = _WORD_RE.findall(text)
    return "-".join(tokens[:3])


def _safe_slug(s: str) -> str:
    s = s.lower()
    s = re.sub(r"[^a-z0-9-]+", "-", s)
    s = re.sub(r"-+", "-", s).strip("-")
    return s[:80] or "untitled"


def _slug_to_title(slug: str) -> str:
    return " ".join(w.capitalize() for w in slug.replace("-", " ").split())


def _extract_tokens(ev: dict[str, Any]) -> list[str]:
    """Pull a coarse bag-of-tokens out of an event for co-occurrence detection.

    R13 (super-patch 2026-07-05): returns at most ``_MAX_TOKENS_PER_EVENT``
    DISTINCT tokens. The co-occurrence detector pairs these tokens pairwise
    (O(n²)); without a cap a single event carrying tens of thousands of unique
    strings would blow up the pair count. Tokens are de-duplicated as they are
    collected (previously the detector's ``sorted(set(...))`` did the dedup), so
    the final token set for a realistic event is unchanged.
    """
    seen: set[str] = set()
    out: list[str] = []

    def _add(tok: str) -> None:
        if tok and tok not in seen:
            seen.add(tok)
            out.append(tok)

    for field in ("evaluated", "acted"):
        if len(out) >= _MAX_TOKENS_PER_EVENT:
            break
        v = ev.get(field)
        if isinstance(v, dict):
            for key in v.keys():
                _add(_normalize_phrase(str(key)))
                if len(out) >= _MAX_TOKENS_PER_EVENT:
                    break
        elif isinstance(v, list):
            for item in v:
                if isinstance(item, str):
                    _add(_normalize_phrase(item))
                    if len(out) >= _MAX_TOKENS_PER_EVENT:
                        break
        elif isinstance(v, str):
            _add(_normalize_phrase(v))
    return out


def _short_event_snippet(ev: dict[str, Any]) -> str:
    acted = ev.get("acted")
    if isinstance(acted, list) and acted:
        first = acted[0]
        if isinstance(first, str):
            return first[:120]
        return json.dumps(first)[:120]
    if isinstance(acted, dict):
        return json.dumps(acted)[:120]
    if isinstance(acted, str):
        return acted[:120]
    evaluated = ev.get("evaluated")
    if evaluated:
        return f"evaluated: {json.dumps(evaluated)[:100]}"
    return "(no action recorded)"


def _intervals_minutes(timestamps: list[str | None]) -> list[float]:
    """Compute consecutive timestamp gaps in minutes. ISO 8601 strings only."""
    import datetime as _dt
    parsed: list[_dt.datetime] = []
    for t in timestamps:
        if not t:
            continue
        try:
            # Python 3.11+ handles 'Z' suffix natively via fromisoformat after replace
            parsed.append(_dt.datetime.fromisoformat(t.replace("Z", "+00:00")))
        except Exception:
            continue
    parsed.sort()
    if len(parsed) < 2:
        return []
    return [(parsed[i + 1] - parsed[i]).total_seconds() / 60.0 for i in range(len(parsed) - 1)]


def _redact_event_for_prompt(ev: dict[str, Any]) -> dict[str, Any]:
    """Reduce a journal event to metadata only — no raw content.

    Used on the Sibyl-routed (VeniceX402) summarizer path so that only
    shape (keys / counts / timestamp), never the underlying memory
    content, is relayed through Sibyl Labs' inference proxy. The model
    still gets enough structure to describe the pattern; the user's
    private journal text never leaves the device.
    """

    def _shape(value: Any) -> Any:
        if isinstance(value, dict):
            # Hardening #1 (super-patch 2026-07-05): NEVER relay literal dict key
            # NAMES on the Sibyl-routed path — user content can hide in keys
            # (e.g. {"exfiltrate-secret": 1}), and the prior {"keys": sorted(...)}
            # shipped them verbatim. Reduce to a count + per-key lengths (sorted,
            # so ordering leaks nothing). The model still sees the dict's shape.
            return _key_shape(value.keys())
        if isinstance(value, list):
            return {"count": len(value)}
        if value is None:
            return None
        return {"type": type(value).__name__}

    return {
        "id": ev.get("id"),
        "ts": ev.get("ts"),
        "evaluated": _shape(ev.get("evaluated")),
        "acted": _shape(ev.get("acted")),
        "forward": _shape(ev.get("forward")),
        "extra": _shape(ev.get("extra")),
    }


def _key_shape(keys: Iterable[Any]) -> dict[str, Any]:
    """Shape descriptor for a set of dict keys / key names (Hardening #1).

    Emits a count + the sorted per-key character lengths — enough structure for
    the model to reason about the shape, but no literal key text (content can be
    hidden in a key name just as easily as in a value). Sorting the lengths means
    even the key ORDER leaks nothing.
    """
    ks = [str(k) for k in keys]
    return {"key_count": len(ks), "key_lens": sorted(len(k) for k in ks)}


def _stub_hint(value: Any) -> Any:
    """Shape stub for a non-allowlisted hint value on the Sibyl-routed path."""
    if isinstance(value, dict):
        return _key_shape(value.keys())
    if isinstance(value, list):
        return {"count": len(value)}
    if isinstance(value, str):
        return {"type": "str", "len": len(value)}
    if value is None:
        return None
    return {"type": type(value).__name__}


# Hardening #11 (super-patch 2026-07-05): the hint redaction was a DENYLIST
# (_CONTENT_DERIVED_HINTS) — anything NOT explicitly named passed through raw, so
# any future content-derived hint field would leak by default. Inverted to an
# ALLOWLIST: only these known pure-shape / numeric hint keys survive verbatim.
# `shared_keys` is handled separately (it carries evaluated key NAMES, which are
# content per Hardening #1, so it is shaped, not passed through). EVERYTHING else
# is stubbed. A new hint field now has to be added here deliberately to ship.
_PURE_SHAPE_HINTS = ("hits", "cadence_minutes", "cov", "confidence")


def _redact_hints_for_prompt(hints: dict[str, Any]) -> dict[str, Any]:
    """Reduce hints to shape for the Sibyl-routed (VeniceX402) path.

    ALLOWLIST semantics (Hardening #11): only pure-shape / numeric hints
    (``hits, cadence_minutes, cov, confidence``) are relayed as-is. ``shared_keys``
    carries evaluated key NAMES, so it is reduced to a count + per-key lengths
    (Hardening #1), never the literal names. Every other field — including any
    future content-derived hint — is stubbed to a shape descriptor so no
    normalized memory fragments leave the device. The original hints dict is left
    untouched; only the prompt copy is reduced.
    """
    out: dict[str, Any] = {}
    for key, value in hints.items():
        if key in _PURE_SHAPE_HINTS:
            out[key] = value
        elif key == "shared_keys":
            # Hardening #1: shape the key names, do not relay them.
            out[key] = _key_shape(value) if isinstance(value, list) else _stub_hint(value)
        else:
            out[key] = _stub_hint(value)
    return out


def _build_summarization_prompt(
    pattern_kind: str,
    events: list[dict[str, Any]],
    hints: dict[str, Any],
    *,
    redact: bool = False,
) -> str:
    """Build the LLM prompt for BYOK / Venice summarizers. The prompt is
    deliberately compact.

    When ``redact`` is True (the Sibyl-routed VeniceX402 path), event
    payloads are reduced to metadata only — keys / counts / timestamps,
    no raw content — to honor the contract that only the prompt summary,
    never the underlying memory content, leaves the device. When False
    (BYOK), full evidence is included so the user's own model can produce
    a high-quality skill body; the user controls that destination.
    """
    shown = events[:10]
    if redact:
        evidence = [_redact_event_for_prompt(ev) for ev in shown]
        evidence_label = "Matching journal events (metadata only, up to 10 shown)"
        hints_for_prompt = _redact_hints_for_prompt(hints)
    else:
        evidence = shown
        evidence_label = "Matching journal events (up to 10 shown)"
        hints_for_prompt = hints
    return (
        f"You are summarizing a detected behavioral pattern from a personal "
        f"agent's memory journal.\n"
        f"Pattern kind: {pattern_kind}\n"
        f"Hints: {json.dumps(hints_for_prompt, indent=2)}\n\n"
        f"{evidence_label}:\n"
        f"{json.dumps(evidence, indent=2)}\n\n"
        f"Write a concise reusable skill in Markdown. Include: a clear title, "
        f"one-paragraph description of when to apply this skill, an enumerated "
        f"recipe of the steps the agent should follow, and any constraints "
        f"observed in the source events. Be terse and actionable."
    )


def _row_to_proposal(row: Any) -> SkillProposal:
    """Convert a sqlite3.Row into a SkillProposal dataclass."""
    return SkillProposal(
        id=row["id"],
        tenant_id=row["tenant_id"],
        pattern_kind=row["pattern_kind"],
        proposed_slug=row["proposed_slug"],
        proposed_title=row["proposed_title"],
        proposed_body=row["proposed_body"],
        evidence=loads(row["evidence"]) or [],
        confidence=float(row["confidence"]),
        summarizer=row["summarizer"],
        status=row["status"],
        created_at=row["created_at"],
        reviewed_at=row["reviewed_at"],
        review_note=row["review_note"],
        accepted_doc_key=row["accepted_doc_key"],
    )
