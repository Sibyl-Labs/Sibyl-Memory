# Changelog

All notable changes to `sibyl-memory-mcp` are recorded here. Format follows
[Keep a Changelog](https://keepachangelog.com/en/1.1.0/). Versioning follows
[SemVer](https://semver.org/).

## [0.4.0] - 2026-10-31

One release: the paid tier R2 line, the shipped 0.9.0 family fixes it was built beside, the graph line (tiered retrieval and relations) and the release merge items below.

### Release summary
- New tools: `memory_link`, `memory_unlink`, `memory_neighbors`, `memory_get_reference`,
  `memory_list_references`, `memory_delete_reference`; `links=` on `memory_remember`,
  `scope=` / `with_links=` on `memory_search`. Read results stay inline in Claude Code.
- `memory_recall` shows a record's owning hubs and siblings.
- Pro: every memory tool records a skill signal (name and an argument-shape hash only).

### Release merge (2026-10-28)
- `memory_recall` adds `hubs`, `siblings` and `siblings_omitted` for an entity that hub entities link
  to with `source_of` (`neighborhood_note` instead when the neighborhood read fails; the recall never
  fails for it). On by default; `SIBYL_MEMORY_RECALL_HUBS=0` turns it off; tuning
  `SIBYL_MEMORY_RECALL_SMALL_HUB_MAX` / `SIBYL_MEMORY_RECALL_SIBLING_CAP` (60). Anyone who already
  has `source_of` edges sees the recall payload gain these keys.
- The seven graph tools carry the R2 skill-signal wrapper too (`@_recorded`), so every memory tool
  records; the tool schemas the host sees are unchanged (fixture test against the graph merge).
- The experimental tool-text variant from the bench line (`SIBYL_MEMORY_TOOLTEXT_V2`) is not shipped.
- Usage count keeps the opt-out default (`SIBYL_MEMORY_TELEMETRY=0`); Hermes turned its own off.
- Requires `sibyl-memory-client>=0.10.0`, `sibyl-memory-hermes>=0.6.0`.
- Tests: `test_recall_hubs_2026_10_28.py` (8), `test_telemetry_default_2026_10_28.py` (2).

### Paid tier R2: skill signals (built 2026-09-29)

Spec plugin-paid-tier-r2-spec-2026-09-29 section 1.2. Requires sibyl-memory-client 0.10.0.

### Added
- Skill signals: every memory tool the server handles is one tool event (name and the 12-hex
  fingerprint of its sorted top-level argument names; never a value), on the success and the
  error path, through a `_recorded` wrapper that keeps the tool signature the host sees. Pro only
  (the cached client's verified entitlement); no client, no record. Entity writes are recorded
  by the client as hashes. The session is the process's lifecycle session. The server sees only
  its own tools: on Codex, Cursor and other MCP hosts the sequence signal covers the memory tools.

### Tests
- `tests/test_signals_capture_2026_09_29.py` (6): all eight tools record a name and a 12-hex
  shape; the error path records; free, signed out and recording off record nothing; canaries
  (values, entity name, query, keys) never on disk; the listed tool schemas are unchanged.

### Fixed (R2 check fixes, 2026-09-30)
- R2F-2: in Claude Code with the sibyl Stop hook wired (`_save_is_hooked()`), the server records
  no tool event: the hook's transcript slice already holds these calls and is the record of truth
  there, so each memory tool was counted twice. Other hosts, and Claude Code without the hook,
  record as before. Entity writes (the client's, as hashes) are unaffected.
- R2F-N4 (README): the signals file keeps tool and MCP server names in plain text.
- Tests: +3 in `test_signals_capture_2026_09_29.py` (Claude Code with the hook: no tool event;
  Claude Code without it and another host: all eight recorded). 136 passed.

### Tiered retrieval and relations (graph line, built 2026-10-22)

### Fixed - read results stay inline in Claude Code (output budget, 2026-10-22)
- V1 search hits (1,500-char body prefix + 600-char snippet + title + links) made
  `memory_search` ~95,000 wire chars / ~24,000 est. tokens at limit=30 on a 2-20 KB-body
  store. Claude Code saves an unannotated MCP result over 50,000 chars, or over
  `MAX_MCP_OUTPUT_TOKENS` (default 25,000 tokens), to a file instead of inlining it
  (code.claude.com/docs/en/mcp, "MCP output limits and warnings"); agents without a
  file-read tool saw nothing.
- The read tools (`memory_recall`, `memory_search`, `memory_list`, `memory_neighbors`,
  `memory_get_reference`, `memory_list_references`) declare
  `_meta["anthropic/maxResultSizeChars"] = 200000` in tools/list; Claude Code then uses that
  value instead of the 50,000-char line "regardless of what MAX_MCP_OUTPUT_TOKENS is set to".
- Every read result is held, on its WIRE text (FastMCP's indent=2 JSON, fence and a notice
  reserve included), to an ESTIMATED token budget (`ceil(ascii/4) + non-ASCII chars`;
  default 22,000; `SIBYL_MEMORY_MCP_OUTPUT_TOKENS`, clamped 1,000-125,000) and a hard char
  cap: 190,000 when the session's client is Claude Code, else 45,000 (fallback for hosts
  that do not honour the annotation); `SIBYL_MEMORY_MCP_OUTPUT_BUDGET` (chars, clamped
  4,000-500,000) overrides it. Replaces the 200,000 hits-only budget.
- `memory_search` degrades in order, only when the result does not fit: hits with a
  `snippet` shorten their body prefix (500, 150) then omit it (`body_omitted: true`; `chars`
  stays); snippets shorten to 250 chars re-centred on the first match marker; link
  summaries drop `sample` (`sample_omitted: true`, counts stay); only then trailing hits go.
  The verdict gains `degraded` (steps taken) and, on a drop, `truncated: n` and a `hint`.
- `memory_list`: bodies shortened (500, 150), never omitted, then trailing rows dropped
  (`degraded` / `truncated` / `hint` at the top level). `memory_neighbors` and
  `memory_list_references` page to the same budget (cursor resumes after the last row
  shown). `memory_get_reference` cuts a page that would not fit (`page_capped: true`).
- Measured (Claude Code session, limit 50, 120 entities + 120 docs): English 158,638 chars /
  39,697 est. tokens -> 84,020 / 21,005, all 50 hits; JSON-heavy 42,287 -> 20,812 tokens;
  CJK 78,200 -> 12,143 tokens, all 50 hits. Search p50 unchanged within noise.

### Changed - Edge identity (V1 panel theme A, 2026-10-22)
- `memory_remember` returns `inherited_links: n` when it CREATED the entity and n edges
  were already keyed to its name (written for an earlier, forgotten entity of that
  name); those edges read `stale: true` until re-linked or unlinked.
- `memory_link` returns `changed` (an existing edge's metadata updated or its endpoints
  re-stamped; an identical re-link is a no-op).

### Fixed - V1 panel, graph read side (2026-10-22)
- `memory_neighbors` returns the queried node with `exists` / `archived`, plus a `note`
  when it does not exist (exact, case-sensitive names) or is archived; edges carry
  `stale` (true when the edge was written for an earlier entity of that name; never for a
  dangling or archived end); `degree` counts a self-loop once.
- `memory_remember` / `memory_set_reference` report `links: {created, updated, unchanged}` (was the
  number of specs passed).
- `memory_search` never fails on a damaged links index: hits come back with
  `links: null` and `verdict.decoration_note`; the verdict also carries `links_ms`.
  Hit `links.sample` is one edge per relation (largest first, at most five) and `hub: true`
  marks a node above 500 edges in one direction.

### Fixed - V1 panel (PANEL-SYNTHESIS B, D, E, G; 2026-10-22)
- **Release train.** `version = "0.4.0"`, requires `sibyl-memory-client>=0.10.0` and
  `sibyl-memory-hermes>=0.6.0`. With the old floor a partial upgrade (new server, old
  client) died at import (`count_tiers`; YARROW mcpskew). Floor-compat tests import the
  server and the Hermes provider against the floor client tree, and show the 0.9.0
  client (git 708bd89) cannot serve this server.
- `memory_search`: `verdict.name_matches` is recomputed when the output budget drops
  rows, like `returned` and `tiers_hit`.
- `memory_delete_reference(key, force=False)`: `skill/` and `debloat/` keys are refused
  without `force=true` (VALIDATION_ERROR naming the owning feature; the account gate
  still answers first). Returns `edges_removed`, and `proposals_superseded` when an
  accepted skill proposal pointed at the document.
- `chars` means the stored length on every reference tool: `memory_get_reference`
  now reports the stored length as `chars` and the fence-scrubbed length as
  `surfaced_chars`; `offset` / `next_offset` stay in surfaced coordinates.
- Argument-validation errors name the parameters at fault: `missing`, `unknown`,
  `invalid` (names only, identifier-shaped, at most 10 each; values are never echoed,
  SEC-14 unchanged). `memory_link(from=..., to=...)` now says `from_node` / `to_node`.
- Tool text: `memory_forget` says links are kept and reconnect `stale` on re-create;
  `memory_set_reference` asks for `metadata.status`. README: upgrade-together note,
  delete row.
- Tests: `test_v1_panel_fixes_2026_10_22.py` (13); reference-tool tests updated for
  `surfaced_chars` and `edges_removed`.

### Changed - Agent guidance (tiered-retrieval spec section 3, 2026-10-22)
- `memory_remember`'s description says which tier: an entity is a card (under about 1 KB)
  for a thing you will name again, a long text is a reference document, hubs keep
  membership in links written with the node. The module docstring's `memory_search` line
  mentions name-first results, `scope` and the hit fields.
- README: "Tools exposed" lists all 15 tools plus how agents should use them (write a card,
  link the documents, read top-down); "8 tools" -> 15 throughout.

### Added - Tier-aware `memory_search` (tiered-retrieval spec 2.C, 2026-10-22)
- `memory_search(query, limit=10, tiers=None, scope="all", with_links=True)`.
  `scope="graph"` runs the gated engine over entities + state only (the "find
  the hub" call); `scope` with `tiers` -> `VALIDATION_ERROR` (tiers is the raw,
  gate-free path). Unknown scope -> `VALIDATION_ERROR`.
- A query that is an entity's name (or `category:name`) returns that entity
  first, `match: "name"`; up to 3 `name_partial` rows follow.
- Hits carry `match`, `chars`, `title` and (default) `links` (degree, counts by
  relation, up to five sample edges; null on journal hits), one batch query for
  all hits. The raw `tiers=` path gets `chars`/`title`/`links` too (additive; no
  stage 0, gates unchanged). Link samples pass the same fence scrub as bodies.
- Verdict gains `tiers_hit`, `name_matches`, `recall_depth`, `scope`;
  `tiers_hit` is recomputed when the output budget drops rows.
- The tool description teaches top-down reading (resolve name with
  `scope="graph"` -> `memory_neighbors` -> `memory_get_reference`).
- Tests: `test_tier_search_tool_2026_10_22.py` (8).

### Added - Reference tier tools (tiered-retrieval spec 2.A, 2026-10-22)
- Four tools (8 -> 12): `memory_set_reference(key, body, metadata)` -> `{ok, key, chars}`;
  `memory_get_reference(key, offset=0, max_chars=20000)` -> fenced `{ok, key, body, offset,
  chars, next_offset, metadata, updated_at}`, `max_chars` clamped to 1,000-50,000, unknown key
  `{ok: false, code: NOT_FOUND}`; `memory_list_references(prefix, limit=50, cursor)` -> fenced
  `{ok, count, items, next_cursor}` (limit max 200, literal case-sensitive prefix, opaque cursor);
  `memory_delete_reference(key)` -> `{ok, key, deleted}`, a hard delete (`memory_forget` stays
  entity-only).
- Injection handling: the read tool scrubs fence markers out of the WHOLE body before paging, so
  a marker can never straddle a page edge; `offset`/`chars`/`next_offset` count characters of
  that surfaced text. Metadata is scrubbed and capped at 4 KB on reads. The list tool holds the
  total output budget and, when the budget drops rows, sets `next_cursor` right after the last
  row returned so nothing is skipped.
- `memory_set_reference` rejects metadata over 4 KB and numeric/boolean/null bodies
  (`VALIDATION_ERROR`; a document is text, dict/list are stored as canonical JSON). The account
  gate answers before any argument check on every new tool; reads stay allowed under the
  computer-limit read-only policy and the two writes are refused there.

### Added - Relations tools (tiered-retrieval spec 2.B)
- `memory_link(from_node, to_node, relation, metadata=None)` -> `{ok, id, created}`;
  `memory_unlink(from_node, to_node, relation=None)` -> `{ok, removed}`;
  `memory_neighbors(node, relation, direction, tier, category, limit, cursor, preview)` ->
  fenced `{ok, node, edges, count, degree, next_cursor}`. Parameters are `from_node` /
  `to_node` because `from` is not a legal Python parameter name. NodeRefs are JSON objects;
  a JSON string or a bare `{category, name}` entity is accepted. Results are fence-scrubbed
  (MH-1) and held to the total output budget (MH-2); when the budget drops edges,
  `next_cursor` resumes right after the last returned edge. All three are gated like every
  memory tool. With the reference tools the server lists 15 tools (module docstring updated).
- `memory_remember(..., links=None)`: the entity and its outgoing edges in one transaction
  (strict endpoints; `NOT_FOUND` writes nothing).
- `memory_set_reference(..., links=None)`: the document and its outgoing edges in one
  transaction, same coercion (`_coerce_links`) and limits (at most 1,000 edges, strict
  endpoints) as `memory_remember`; a bad edge rolls back the document write too. The result
  carries `links` (edge count) when edges were given.

### Changed - search hit shape (tiered-retrieval spec 2.D, 2026-10-22)
- `memory_search` hits carry `chars` (the full body length), so an agent can
  tell whether the 1,500-char body is the whole thing.
- The hit `snippet` (now a 40-token match-centred window from the client) has
  its own 600-char cap.

## [0.3.0] - Unreleased

Account-gated release (spec account-gated-plugin-spec-2026-09-27, 3.2).

### 2026-10-14 - Pre-release cleanup
- README and package docstring: wiring now leads with `sibyl setup claude-code` and
  `sibyl setup codex`. The manual Codex snippet is the `[mcp_servers.sibyl_memory]` table that
  Codex actually reads (the old `[[mcp_servers]]` snippet is not a form Codex accepts), and the manual
  Claude Code form is `claude mcp add --scope user`.
- README: `memory_search` covers entities, state, reference docs and the journal; all tiers get
  the same 8 tools; `SIBYL_TENANT_ID` is no longer listed as a server override (the server
  never read it).
- Docker: the trailing comment on the repo `Dockerfile`'s `FROM` line (a syntax error) moved to
  its own line; the image has not been rebuilt yet. `docker-compose.yml` no longer passes
  `SIBYL_TENANT_ID`.
- Tool descriptions are shorter: version history moved out of them, so each session loads about
  215 fewer tokens. Tool names, arguments and results are unchanged.
- Comments, docstrings and this CHANGELOG describe each finding by what it fixed instead of
  naming testers or internal QA rounds. Text only; no code changed.

### Added (agent handoff messages, 2026-10-06)
Spec agent-handoff-messages-spec-2026-10-03 (rows M1 to M7; needs sibyl-memory-client 0.9.0).
- The handoff envelopes (`ACCOUNT_REQUIRED`, `CAP_EXCEEDED`, `TIER_GATED`,
  `TIER_VERIFICATION_FAILED`) gain `next` (a command, `done`, `retry` or `retry in N minutes`)
  and `human_action` (a sentence or `null`; the key is always present), read from the client
  exception. Every existing key and value is unchanged; the new keys come after them.
  `ACCOUNT_REQUIRED`'s `message` is the exception's `summary`, the same text as before.
- `NOT_FOUND`, `VALIDATION_ERROR` and `ERROR` are not handoffs and carry neither key. Successful
  results and the `notice` line are unchanged. The bare-JSON unwrap still matches.
- Tests: `tests/test_handoff_2026_10_03.py` (+24, including an exact nine-key assertion on the
  account envelope). Suite: 151 passed.

### Added (paid tier R1, 2026-09-29, R1B-3)
- Every tool call counts active time; on Pro a successful result may carry the automatic-save
  request (`Sibyl Memory Pro: about 60 minutes of work since the last save. Run the save
  procedure now in headless mode ...`), once per interval, never on an error. Order: account
  notice, save request, skill-proposals line. Inside Claude Code (initialize `clientInfo.name`)
  with our Stop hook wired, the hook carries the request instead (both host spellings are
  Claude Code: `claude code`, sent by Claude Code 2.1.285, and `claude-code`; R1B-6 names them in
  one constant and tests both). A one-time tier-change line.
- The process-start thread runs the local learner after the debloat plan (Pro).

### Added (save and debloat, 2026-09-27, SD-3)
Spec plugin-save-debloat-spec-2026-09-27 (same coordinated release; version unchanged).
- Prompts `save` (mode run, preview, setup, headless, curate) and `debloat` (mode measure,
  trim): the procedure text, the installed `~/.sibyl-memory/skills/` file when present (a
  person's edit is honoured), else the shipped text. In Claude Code: `/mcp__sibyl-memory__save`.
- Resources `sibyl://skills/SAVE.md`, `sibyl://skills/DEBLOAT.md` (text/markdown),
  `sibyl://skills/manifest` and `sibyl://context/weight` (application/json, stat only).
- Prompts and resources are never gated; the tools the procedures call are gated as before.
- A successful result may carry ONE lifecycle line when the account has nothing to say: the
  Pro context-trim report (once per process), the unsaved-last-session line, or a free save-due
  / debloat-due reminder. Never on errors. `sibyl reminders off` silences them.
- On Pro the first client of the process runs the debloat plan under the person's policy in a
  daemon thread (Codex, Cursor and other MCP hosts start a server per session).

### Tests (save and debloat)
- `test_lifecycle_prompts_2026_09_27.py` 8 (prompts, validation, resources with a read spy,
  no-credentials access, notice precedence and throttle, Pro start report, free never applies).

### Fixed (independent check of save and debloat, 2026-09-27, SD-7)
- The server enables write counting on every client it builds (`enable_lifecycle_counting`); the
  SDK alone no longer counts. Automatic trims are matched per file path (client).

### Changed (independent check fix batch, 2026-09-27, GATE-15)
- The first tool result after the client moves pre-sign-in rows into the
  account carries `notice`: "N memories written before sign-in were moved
  into your account on this computer." (once; no code change here, the client
  gives it out through `entitlement_notice()`).
- README: the paid tier is `pro` (the tier list named retired plan names); the
  privacy paragraph says the size check and the usage count also carry this
  computer's signed access token (account id, tier, cap, device hash, account
  flags; no personal data).
- Tests: 2 in `test_account_gate_2026_09_27.py` (the notice once, not repeated
  by a rebuilt server; fails before) and no notice without pre-sign-in rows
  (a guard, passes before and after).

### Tests (gate fix before the independent check, 2026-09-27)
- A signed-in server lists rows a pre-account install wrote under the default
  tenant (client 0.9.0 adopts them on the first gated call); credentials with
  no entitlement and the api unreachable answer `ACCOUNT_REQUIRED` with reason
  `setup_incomplete` (client 0.9.0 no longer grants a 7-day bootstrap grace),
  also after `entitlement.json` is deleted. No mcp code change: the envelope
  passes the new reason through (the server docstring's reason list names it).
- conftest: the network guard is installed at import and every test fails if
  it attempted a non-loopback connection or lookup, even one it caught;
  `test_network_guard_2026_09_27.py` proves the guard.

### Changed
- **An account is required.** There is no pre-activation free local mode any
  more. The server still starts and `list_tools` still lists the 8 tools (so
  an agent can see them and learn why they refuse), but with no activated
  account holding a valid entitlement every tool returns a ToolError
  (`isError: true`) whose text is bare JSON: `{"ok": false, "error":
  "EntitlementError", "code": "ACCOUNT_REQUIRED", "reason": <no_account |
  signed_out | expired_offline | under_review | account_deleted |
  invalid_entitlement | wrong_device | policy_read_only | policy_none |
  client_too_old>, "message": <plain-language copy>, "recovery", "account_url"}`.
  Other errors keep FastMCP's `Error executing tool <name>: {json}` text.
- The gate lives in sibyl-memory-client; the server passes it the credentials
  path it reads (`SIBYL_CREDENTIALS` or `~/.sibyl-memory/credentials.json`).
  `sibyl init` on a running server takes effect on the next call: the cached
  client is rebuilt when credentials.json changes or the token in
  entitlement.json changes (fingerprinted, so the gate's own bookkeeping
  writes do not rebuild it).
- The `memory_search` short-query guard (under 3 characters) asks the gate
  first, so it cannot answer without an account either.
- Successful results can carry `notice` (offline grace running out, email
  nag), at most once per process per 24 h per text; never on errors, never a
  token.
- The HMAC credentials claim (with email and wallet) is no longer built:
  client 0.9.0 sends the server-signed entitlement on `/check-write` instead.
- Dependency floors: `sibyl-memory-client>=0.9.0`, `sibyl-memory-hermes>=0.5.0`.

### Compatibility
- Verified in a fresh venv with the five built wheels against hermes-agent
  0.19.0 (current on PyPI at build time): `memory_list` with no account returns
  the ACCOUNT_REQUIRED envelope, not a Python exception.

## [0.2.1] - 2026-09-06

### Changed
- **Dependency floor raised to `sibyl-memory-client>=0.8.1`.** 0.8.1 carries the
  Darwin trust-store fix (macOS framework-build Pythons could not verify
  api.sibyllabs.org) and the cross-tier IDF corpus count. Without the floor a
  `pip install -U sibyl-memory-mcp` could leave an unpatched client underneath,
  which is the hazard the 0.7.0 floor bump closed the last time.
- The `Operating System :: OS Independent` classifier was wrong and is replaced
  by `Operating System :: POSIX :: Linux` and `Operating System :: MacOS`.
  Sibyl Memory runs on Linux, macOS (Apple Silicon and Intel), and Windows
  through WSL2. Native Windows is not supported. Classifiers are
  informational; pip does not enforce them, and WSL2 installs look like Linux
  to pip, which is correct.
- The one-probe-per-zero cost pin in `test_verdict_contract_2026_08_31.py` now
  reads four `COUNT(*)` instead of one, because client 0.8.1 made the IDF
  corpus count cross-tier. The regression it guards, a DOUBLE walk of the
  tables on a single zero, is still exactly what it fails on.

### Fixed
- User-facing copy corrected from 2 MB to 5 MB to match the free-tier cap
  raised in `sibyl-memory-client` 0.5.0. No behaviour change.

## [0.2.0] "Lucid" - 2026-08-31

Minor version, not a patch: the `memory_search` **response schema changed**. Every
response, including every zero, now carries an additive `verdict` object, and a
client that pins the old flat `{ok, query, count, results}` shape should read this
entry before upgrading. Nothing was removed from the response and no field changed
meaning.

- Floors `sibyl-memory-client>=0.8.0` and `sibyl-memory-hermes>=0.4.0`. The verdict
  is produced by the client and forwarded by this server, so an MCP server on the
  new response schema over an old client would advertise a field the engine below
  it cannot fill. The hermes floor is there for the same reason: this package's
  install can pull the provider, and pip's default only-if-needed upgrade strategy
  leaves an already-satisfying older sibling in place, which is exactly the
  packaging hazard the 0.1.14 floor raise was for.
- **Docker-image users must rebuild.** A self-built `sibyl-memory-mcp` image pins
  its dependencies at image build time; a `pip install -U` on the host does not
  reach inside it. Rebuild the image to pick this up.

### Added
- **`memory_search` responses now carry a `verdict`** (branch
  `lang-core-verdict`, 2026-08-31). Until this release `server.py` called
  `multi_record_search(client, query, limit=safe_limit)` with **no
  `diagnostics=` kwarg**, so the SDK's optional explanation channel — which had
  existed since 0.1.14 — was unreachable from the tool an agent actually calls.
  A `count: 0` reached the agent as `{ok, query, count, results}` and could not
  be told apart from an empty store. The verdict now rides on the RETURN of
  `multi_record_search`, so there is no call-site kwarg left to forget, and the
  response gains one additive, bounded `verdict` object naming exactly one of
  `abstained_on` / `negation_abstain` / `gated` / `empty_store` / `no_match`,
  with `recovery` and a plain-language `explain`.
- The verdict passes through `_scrub_value` and sits beside the fenced payload.
  It carries numbers, enum values and the caller's own query tokens — never
  stored-record text — so it composes with the MH-1 fence and the MH-2 output
  budget rather than becoming a second, unfenced channel out of the store. It is
  reconciled against `count` after `_bound_hits`, so the two can never disagree.
- **The `_MIN_QUERY_LEN` short-query guard names a cause too.** It was the one
  place a `count: 0` shipped with nothing attached at all.
- The tier-filtered (`tiers=`) path carries a verdict as well: bypassing the
  linker does not bypass the contract.

### Changed
- **The `memory_search` docstring no longer teaches `tiers="entity"` as the
  escape hatch from an abstention.** That advice routed around every precision
  gate, including the one that makes injection-shaped queries return nothing. It
  is replaced by the cause-scoped recovery: on `abstained_on`, drop the one token
  named in `verdict.tokens[0]` and retry with every gate still armed, at most
  twice. `tiers` remains documented as the linker bypass, with its precision
  tradeoff stated. **No server-side auto-retry** — the loop stays agent-side,
  because a silent server-side retry is indistinguishable from the silent zero
  this contract deletes. A test asserts the server calls `multi_record_search`
  exactly once per request.

### Unchanged
- Search behaviour is untouched. The MCP stdio path is byte-identical to
  `ef98f5b` on every quality field of the full multilingual battery.

### Fixed (independent adversarial review, 2026-08-31)
- **The empty-store probe ran twice on the default path** (8 `COUNT(*)` per zero
  where the pre-contract build took 1): the engine resolves `EMPTY_STORE` at its
  own single exit, and this tool called `refine_zero` on top. `refine_zero` now
  runs on the `tiers` branch only, where `client.search` genuinely does not
  probe. Back to 1 `COUNT(*)` per zero.
- The no-server-retry test asserts the absence of `ast.For` / `ast.While` rather
  than grepping for the words, which had it firing on the tool docstring and on a
  legitimate generator expression. The docstring's cause names are now asserted
  against the `VerdictCode` values, so a rename cannot ship a stale instruction
  to the agent with a green suite.

## [0.1.14] - 2026-08-22

### Changed
- **Dependency floor raised to `sibyl-memory-client>=0.7.0`, closing a
  packaging hazard** (an external contributor, independent verification, 2026-08-18): the
  prior floor (`>=0.5.0`) meant `pip install -U sibyl-memory-mcp` alone was a
  silent no-op once a newer client existed on PyPI — pip's default
  only-if-needed upgrade strategy leaves an already-satisfying older client in
  place, so an MCP-only install (a self-built Docker image, a `pipx`-isolated
  install, anything not going through `sibyl-memory-cli`'s tighter floor)
  could sit on unpatched retrieval code indefinitely while reporting a clean
  install. Picks up the client 0.7.0 N4/N5/N1'-diagnostics fixes.
- **`memory_search` docstring documents the default-path abstention
  contract.** No behavior change — the untiered path has always been able to
  return `count: 0` on an ordinary paraphrase carrying one unsupported content
  word, indistinguishable from an empty store. The docstring now says so
  explicitly and tells a caller to retry with `tiers="entity"` (or the
  expected tier) when a query that should match returns nothing.

## [0.1.13-fixes] - 2026-08-16 (folded into 0.1.13, no separate release)

### Fixed
- **Default `memory_search` path (tiers omitted) now answers question-shaped
  queries.** No `server.py` change — the untiered path routes through the client's
  `multi_record_search`, which previously abstained (`count == 0`) whenever a
  query carried a zero-support *function* word (`kiedy`, `gdzie`, `when`, `who`,
  `how`, ...). The client's N1 fix classifies zero-df tokens so function-shaped
  ones are dropped while content-shaped absences (injection / `rejected` class)
  still abstain. Default-path recall on a PL/EN question battery went **1/8 →
  8/8**; the tool-boundary abstention contract is unchanged (`co0001
  nonexistenttokenzzzq report` and `was the co0001 order rejected` still return
  `count == 0`). Requires `sibyl-memory-client` with the N1/N2/N3 recall fixes
  (0.6.x follow-up to 0.6.0). New coverage:
  `tests/test_default_path_recall_2026_08_16.py`.

### Added
- **First-party Docker packaging (repo-root `Dockerfile`,
  `docker-compose.yml`, `.dockerignore`) and a README "Run with Docker"
  section.** Non-root user, pinned slim Python base, no secrets baked in,
  memory on a mounted volume. These are repo-level infra and docs only: the
  published wheel contents are unchanged at the time this section was written
  — see 0.1.14 above, which is the release that actually needed a version
  bump for retrieval fixes. The Docker files ship via the GitHub source sync.
  **Caveat surfaced 2026-08-22**: an image built with `docker build` from this
  Dockerfile bakes in whatever `sibyl-memory-client` is on PyPI at BUILD time
  (`pip install /app/sibyl-memory-mcp` inside the image, not a floating
  install) — rebuild the image (`docker build -t sibyl-memory-mcp:local .`)
  to pick up a newer client; a running or previously-built container does not
  update itself.

## [0.1.13] - 2026-08-06

### Changed
- **Dependency floor raised to `sibyl-memory-client>=0.5.0`** to pick up
  multi-language search (schema v4). The untiered `memory_search` path (which
  routes through the client's `multi_record` linker + `MemoryClient.search`) now
  resolves non-ASCII / non-Latin / CJK / Thai / compound-token queries that
  previously returned nothing — a 100-language write+query sweep went from 21/100
  to 100/100. No `server.py` code change: the improvement is entirely in the
  client the MCP server calls. See `sibyl-memory-client` 0.5.0.

## [0.1.12] - 2026-07-05

Super-patch: recovery + adjudication of the remaining Fable 10-lens audit
findings (`plugin-hardening-superpatch-plan-2026-07-05.md`).

### Fixed
- **Client-cache rebuild dropped the old `MemoryClient` without closing it
  (R26).** `_open_client` rebuilds the cached client on a `credentials.json`
  mtime change (or post-init/post-logout appearance/disappearance), but
  discarded the previous client directly, stranding every per-thread SQLite
  connection it had registered. Repeated credential-mtime changes
  accumulated open connections. The old client's storage is now closed
  (best-effort — a missing/failing `close()` never blocks serving the newly
  built client) before the cache is swapped.
- **`~/.sibyl-memory` could be created world-readable on first touch (R30).**
  `_build_client` used a bare `mkdir(parents=True, exist_ok=True)` with no
  mode; on an already-existing directory `mkdir`'s mode argument is a no-op
  too. The memory directory is now created (and, for the pre-existing case,
  explicitly `chmod`'d) at `0o700`, mirroring the CLI's credential-writing
  path and the client `Storage` hardening.
- **`memory_search` unknown-tier error had no `code` field (R31).** An
  unknown value in the `tiers` CSV param raised a builtin `ValueError`,
  which fell through `_err`'s typed exception chain and produced an error
  envelope with no `code` — inconsistent with every other tool error. It now
  raises the SDK's `ValidationError`, mapped to `code: "VALIDATION_ERROR"`;
  `_err` also gained a fallback `payload.setdefault("code", "ERROR")` so no
  future untyped exception can produce a code-less envelope again.
- **Tenant resolution had no `account_id` fallback rung (Contract T).**
  `_build_client` resolved `tenant_id=creds.get("tenant_id") or
  DEFAULT_TENANT` directly, so an activated account with a missing/empty
  `tenant_id` (legacy credentials, or a present-but-empty field) fell back
  straight to the shared `DEFAULT_TENANT` instead of its own account. Now
  resolves via the canonical ladder shared by every plugin surface:
  `tenant_id -> account_id -> DEFAULT_TENANT`.

### Metadata
- `pyproject.toml`'s `Repository` URL pointed at a foreign, nonexistent
  `sibyllabs` (no hyphen) GitHub org that 404s in live PyPI metadata.
  Corrected to `https://github.com/Sibyl-Labs/Sibyl-Memory` (R27).
- Third-party dependency `mcp` was pinned `>=1.0.0` with no upper bound, so
  a fresh install could auto-pip a future major with breaking changes.
  Capped to `mcp>=1.0.0,<2` (R29). Internal `sibyl-memory-*` pins are
  unaffected (stay `>=`, vendor-controlled names).

## [0.1.11] - 2026-06-25

Pre-launch security audit hardening.

### Security
- Ported the prompt-injection fence + per-call nonce + body/snippet size caps
  onto all four read tools (`memory_recall`, `memory_search`, `memory_list`,
  `memory_get_state`). Previously only the Hermes adapter carried this; the MCP
  server returned raw stored bodies with no fence or size cap.

### Fixed
- `memory_search` early-returns on a sub-3-character query (mirrors the adapter).

## [0.1.10] - 2026-06-19

### Fixed

- **SDK-layer argument-validation errors were plain text, not JSON (beta report
  2026-06-14).** A pydantic validation failure on tool arguments returned an
  `Error executing tool: ...` string instead of the `{ok:false,code,...}` envelope
  the handler-layer errors use, so a fraction of malformed inputs broke a caller's
  JSON parse. The argument-validation guard now emits the same JSON envelope
  (`code: "VALIDATION_ERROR"`); the offending value is still never echoed back
  (SEC-14). Test: `tests/test_arg_validation_leak_2026_06_02.py`.

## [0.1.9] - 2026-06-11

### Fixed

- **`memory_search` silently returned 0 hits on tier typos.** The `tiers` CSV
  param is now validated against the `entity, state, reference, journal`
  whitelist; unknown values (e.g. `entities`) raise a clear `ToolError`
  (`isError=true`) instead of an empty ok result. (bugflow)

## [0.1.8] - 2026-06-06

### Changed

- **Pin `sibyl-memory-client>=0.4.9`.** Picks up the anchor-first hybrid
  multi-record resolver (client 0.4.9): `memory_search` now strict-filters
  multi-record / linked-record queries to the query's anchor cluster while
  keeping high-coverage natural-language evidence, eliminating cross-cluster
  pollution at scale. No MCP code change; routing through `multi_record_search`
  is unchanged.

## [0.1.7] - 2026-06-05

### Fixed

- **Tool errors now set the MCP `isError` flag (agent error-detection).**
  `_err()` previously returned a plain dict, which FastMCP delivered as a
  *successful* tool result (`isError: false`) with the error nested inside the
  payload, so an agent keying off the protocol-level `isError` flag could not
  detect the failure at all. `_err()` now raises `ToolError` carrying the same
  structured payload encoded as JSON, so callers both (a) see `isError: true`
  and (b) can still parse `error`/`code`/`recovery`/`upgrade_url` from the
  message. No tool signatures change; only the error envelope is corrected.
  Regression coverage: `tests/test_err_toolerror_2026_06_05.py`. (bugflow)

## [0.1.6] - 2026-06-04

### Added

- **`tiers` filter on `memory_search`.** The MCP `memory_search` tool now accepts an
  optional comma-separated `tiers` argument (`entity`, `state`, `reference`,
  `journal`). When set, it bypasses the multi-record linker and calls `client.search()`
  directly with the tier filter, so callers can restrict retrieval to a tier subset.
  This resolves journal-entry domination of generic-keyword queries at scale
  (an external contributor, 2026-06-02): journal entries previously accounted for 50-80%+ of hits
  on shared terms like "Project"/"Research"/"Budget", outranking relevant entities.
  Omit `tiers` (or pass null) for the existing all-tier multi-record behaviour. Bumped
  `sibyl-memory-client>=0.4.8` to pull the prefix-mode FTS5 crash fix. Found + verified
  by bugflow; operator-approved.

## [0.1.5] - 2026-06-02

### Security

- **Argument-validation secret-leak guard (SEC-14).** When a caller passed a
  type-invalid argument value (e.g. `limit="sk-live-..."`), the MCP SDK's
  `Tool.run` wrapped the pydantic `ValidationError` as a `ToolError` whose
  message echoed the raw `input_value` back to the wire as an error result, so a
  secret fat-fingered into a typed argument would be reflected to the caller. The
  server now wraps the lowlevel `CallToolRequest` handler (the real dispatch
  path — reassigning `mcp.call_tool` is dead code because FastMCP binds it at
  construction) and replaces any argument-validation error message with a
  generic one that does not echo the value. Bumped `sibyl-memory-client>=0.4.7`
  to pull the cap-bypass + DB link-guard fixes through.

Regression coverage: `tests/test_arg_validation_leak_2026_06_02.py` exercises the
real lowlevel `request_handlers[CallToolRequest]` path and asserts no `input_value`
leak.

## [0.1.4] - 2026-05-30

Coerce-on-Adapter: pairs with the client 0.4.5 structured-body contract.

### Changed

- `memory_remember` / `memory_set_state` coerce a primitive body to `{"value": body}` (new `_coerce_body`), mirroring the hermes adapter. The `body` parameter is widened from `dict` to `Any` so primitives reach the coercion instead of being rejected by FastMCP's pydantic validation at the protocol layer. dict/list bodies pass through untouched.
- Requires `sibyl-memory-client>=0.4.5`.

Regression coverage: `tests/test_coa_coercion_2026_05_30.py` (12 tests, real `call_tool` path). 14/14 suite green.

### Changed (Terminal B — multi-record retrieval, tester Run15)

- **`memory_search` now routes through `multi_record_search`** (new in
  `sibyl-memory-client` 0.4.5) instead of a single `client.search()` pass.
  Workflow queries whose answer spans several linked records now surface them all
  instead of returning only the single strongest match. Same result shape. The
  client pin is already `>=0.4.5`, which ships `multi_record.py`.

## [0.1.3] - 2026-05-28

Beta-tester bug-report remediation (Discord beta report + a test note).

### Fixed

- **First-use writes failed with an opaque `SQLite IntegrityError`
  pre-activation.** With no `credentials.json`, `_build_client()` passed
  `tenant_id=None` *explicitly*, overriding the SDK's `DEFAULT_TENANT`
  default. Every write then violated the `entities.tenant_id NOT NULL`
  constraint while reads + tool discovery still worked — so a broken
  install looked healthy. Now falls back to `DEFAULT_TENANT`, matching
  `sibyl-memory-hermes`' provider behavior. Free local pre-activation
  writes succeed. (Regression test: `tests/test_first_use_tenant.py`.)
- **`__version__` drift.** The hardcoded `"0.1.0"` had drifted from the
  `0.1.2` published wheel. Now single-sourced from installed metadata via
  `importlib.metadata` (mirrors `sibyl-memory-client`), so it can never
  drift again.

### Changed

- Pin bumped to `sibyl-memory-client>=0.4.4` (FTS5 + identifier fixes).

## [0.1.2] - 2026-05-18

External-tester remediation release. v0.1.1 was functionally broken
on PyPI: `pip install sibyl-memory-mcp` followed by the entry-point invocation
raised `ImportError: cannot import name 'CapExceededError' from
'sibyl_memory_client.exceptions'`. Reported by an external tester (independent
third-party install test) after the v0.3.3 family ship.
The 93/93 audit tests passed only because they ran in-tree; there was no
clean-venv install smoke test in CI. Gap closed by the companion
`tmp-test/clean-venv-install-smoke.sh` guardrail.

### Fixed

- **external-test BLOCKER**. `sibyl-memory-mcp` now imports cleanly in a fresh
  venv. The fix lives in the companion `sibyl-memory-client` v0.4.0 which
  exports `CapExceededError` and `TierVerificationError` from the
  `.exceptions` submodule path. This release bumps the client pin to
  `>=0.4.0` to consume that fix and rolls the version forward so anyone
  on `pip install sibyl-memory-mcp` picks up the working release.

### Changed

- `sibyl-memory-client` pin: `>=0.3.3` → `>=0.4.0`.
- `sibyl-memory-hermes` pin: `>=0.3.1` → `>=0.3.2`.

### Notes

- Server code (`server.py`) is unchanged from v0.1.1. The 8-tool surface
  (memory_remember / memory_recall / memory_search / memory_list /
  memory_forget / memory_set_state / memory_get_state / memory_record_event)
  remains stable.
- v0.1.1 has been yanked on PyPI.

---

## [0.1.1] - 2026-05-18

Audit-remediation release. v0.3.0 plugin-family pre-ship audit (2026-05-18T05:05Z)
flagged this package's `memory_record_event` tool as broken end-to-end (every
invocation raised TypeError). This release lands the MCP-side fixes.
Companion releases: `sibyl-memory-client` v0.3.3, `sibyl-memory-hermes` v0.3.1,
`sibyl-memory-cli` v0.1.2.

### Fixed

- **C1**. `memory_record_event` now calls the SDK's actual signature
  ``client.write_event(*, evaluated, acted, forward, extra, ts)``. The
  previous call ``client.write_event(kind, body, category=category,
  name=name)`` referenced parameters that don't exist and raised
  TypeError on every invocation. The high-level (kind, body, category,
  name) contract is preserved by translating: kind+body → `acted={kind,
  body}`, optional category+name → `extra={category, name}`.
- **H2**. `memory_get_state` now unpacks the SDK's `{body, updated_at}`
  return shape into a flat response: `{ok, key, body: <user payload>,
  updated_at: <iso ts>}`. Previously returned `body` containing the full
  wrapper, so "body" meant two different things at different nesting
  depths in the same response.
- **N3**. `memory_list` `category` parameter is now Optional. Matches
  the SDK + Hermes adapter behavior: pass it to filter, omit to list
  across all categories.

### Changed

- **P-H1**. `MemoryClient` is cached at module scope. Previously rebuilt
  on every tool call (reading schema.sql from disk + bootstrapping FTS5
  vtables: 10-50 ms per call). Cache invalidates on credentials.json
  mtime change so `sibyl upgrade` is still picked up without a server
  restart. Net effect: agent recall/search latency drops to single-digit
  milliseconds.
- **memory_search now spans all four tiers** (entities + state +
  reference + journal). Backed by the new `MemoryClient.search()` in
  client v0.3.3. Each hit carries a `tier` tag. The MCP server marketing
  description and tool docstring now match the actual behavior.
- Query sanitization handled by the client SDK (FTS5 column-filter
  syntax can't break out into the parser). MCP server didn't need
  its own sanitization: it's downstream of the SDK fix.

### Security

- **SEC-4 / SEC-11**. `_load_credentials` refuses to follow symlinks.
  Previously called `read_text()` on the resolved path, which would
  silently follow.

### Dependencies

- `sibyl-memory-client>=0.3.3` (was `>=0.3.2`)
- `sibyl-memory-hermes>=0.3.1` (was `>=0.2.2`)

## [0.1.0] - 2026-05-17

Initial release. Operator question 2026-05-17: "currently i'm only seeing
instructions for Hermes agent, how could this be used with claude code or
codex?": answer: an MCP server wrapping `MemoryClient.local()`. Both Claude
Code and Codex CLI consume MCP, so a single server unlocks both.

### Added

- **MCP server** (`sibyl-memory-mcp` console script + `python -m sibyl_memory_mcp`)
  using the official `mcp>=1.0.0` Python SDK with FastMCP convenience layer.
- **8 tools** exposed over stdio transport:
  - `memory_remember`. `set_entity(category, name, body)`
  - `memory_recall`. `get_entity(category, name)`
  - `memory_search`. `search_entities(query, limit)` (FTS5)
  - `memory_list`. `list_entities(category, limit)`
  - `memory_forget`. `archive_entity(category, name, reason)`
  - `memory_set_state`. `set_state(key, body)` (HOT tier)
  - `memory_get_state`. `get_state(key)`
  - `memory_record_event`. `write_event(kind, body, category, name)` (COLD tier)
- **Auto-reads** `~/.sibyl-memory/credentials.json` on every tool call so tier
  changes from `sibyl upgrade` are picked up without restarting the server.
- **Typed error envelope** mapping SDK exceptions to MCP-friendly payloads:
  `CAP_EXCEEDED` (with `upgrade_url`), `TIER_GATED`, `TIER_VERIFICATION_FAILED`,
  `NOT_FOUND`, `VALIDATION_ERROR`. Agents can reason about the right next move.
- **Env overrides**: `SIBYL_MEMORY_DB`, `SIBYL_CREDENTIALS` for non-default
  install locations + multi-account scenarios.

### Design notes

- Re-opens `MemoryClient.local()` on every tool call. SQLite open is
  sub-millisecond and this keeps the server stateless: no stale tier cache
  in the process, every call sees the current credentials.
- Free-tier 2 MB cap is enforced server-side against the database (HMAC-signed
  credentials prevent local tampering). The MCP server has no way to bypass it.
- Tool names are prefixed `memory_` so they namespace cleanly when an agent
  has multiple MCP servers loaded.

### Depends on

- `mcp>=1.0.0` (official Anthropic Python SDK)
- `sibyl-memory-client>=0.3.2` (cap-gate + signed credentials)
- `sibyl-memory-hermes>=0.2.2` (credentials loader)

### Compatible with

- **Claude Code**: add to `~/.claude/settings.json` or project `.mcp.json`
- **Codex CLI**: add to `~/.codex/config.toml`
- **Cursor**: add to `~/.cursor/mcp.json`
- **Continue**: add to `~/.continue/config.json` mcpServers block
- Any other MCP-spec-compliant client.

### License

MIT.
