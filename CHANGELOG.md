# Changelog

All notable changes to memoforge.

The format is loosely based on [Keep a Changelog](https://keepachangelog.com/en/1.1.0/). The version line in `README.md`, `.claude-plugin/plugin.json`, the latest `dist/*.zip`, and the latest `git tag` MUST all match. The `memoforge-0.5.0-probe.zip` archive on disk is a preserved developer-only diagnostic build that proved out §9 of the v0.2.0 postmortem; it is not a release, and `README.md` was deliberately not updated for it.

---

## 1.1.1 — 2026-05-29 (post-validation fixes: Phase 12.5 tidy now runs · WebFetch auto-approve covers Cowork's MCP fetch tool)

**Two fixes surfaced by the 2026-05-29 validation run** (`memo-20260529T084546Z-gdpr-ai-support-transcripts`, a clean `approved_on_v3` finish that itself validated the v1.1.0 wall-clock work — 1h58m, parallel reviewers, monotonic scores 71.8→78.0→87.8, audit log never went dark). No change to memo legal quality.

**Fix 1 — cluttered deliverable folder (Phase 12.5 tidy never ran).** The task folder was left with 7 side-car `live-progress-*.html` snapshots and a stray `_update_state.py` at the top level. Root cause: Phase 12.5 tidy was wired only into the `memo` skill's phase files, but a full run *always* ends via the `continue` skill (the two-segment architecture: `memo` → `source_review_pending` gate, `continue` → `done`), and `continue/SKILL.md` `### done` had **no tidy step at all**. So in normal operation tidy never ran.

**Fix 2 — WebFetch auto-approve never fired (research permission prompts on allowlisted hosts).** During research the user was prompted ~4×, including for obviously-allowlisted hosts (EDPB, ICO). Root cause: in this Cowork environment web fetching is provided by an **MCP tool** (`mcp__workspace__web_fetch`), not the native `WebFetch` — the run's `logs/*-tools.jsonl` show fetches logged as `mcp__workspace__web_fetch` while searches logged as native `WebSearch`. The PreToolUse auto-approve hook matched only `^WebFetch$`, so it never fired for fetches and the curated host allowlist (which already contains `europa.eu`, `ico.org.uk`, …) was never consulted — every research fetch fell through to a manual prompt (~one per researcher subagent, since Cowork's "always-allow" resets across dispatch boundaries).

### Added
- **`scripts/tidy_workdir.py`** (+ `scripts/tests/test_tidy_workdir.py`, 10 tests) — the deterministic, cross-platform engine behind Phase 12.5. Self-guards on `state.json` (skips `failed` / `cancelled_by_user` / `fallback_*` / unfinished), deletes top-level side-car `live-progress-*.html` + stray top-level `*.py` + recursive `*.tmp`, reports what it removed (no silent swallow), and always exits 0 so it can never break a finished pipeline. `--dry-run` / `--json` supported.

### Fixed
- **`skills/continue/SKILL.md` `### done`** now runs the tidy script before end-turn — this is the path that actually executes the ending of every real run, so this is the fix that makes tidy fire.
- **`references/phases/phase-12_5.md`** replaces the inline `find ... -delete` (GNU-find-only; broke silently on a Windows host; swallowed every error) with the `python3 || python` script call.
- **`hooks/hooks.json` WebFetch block** matcher widened from `^WebFetch$` to `^WebFetch$|^mcp__.*fetch$` so it also fires for Cowork's MCP fetch tool (`mcp__workspace__web_fetch`); the inline Python now extracts the URL across input-key shapes (`url`/`uri`/`link`/`href`/`address`/`target`, then a regex scan of any string value) instead of only `tool_input.url`. The host allowlist gate is unchanged — the broader matcher only widens what gets *checked*, so non-allowlisted hosts (law-firm blogs, etc.) still prompt. Verified with a harness that runs the shipped command against native + MCP tool shapes and the allowlist boundary.

### Changed
- **The canonical master `live-progress.html` is now PRESERVED** (only its off-contract `live-progress-*.html` side-cars are deleted). ≤v1.1.0 deleted the master too, relying on the Cowork chat artifact card — but that only persists inside the originating chat, so a delivered / synced / archived folder is better off keeping its one terminal-state dashboard. The `live-progress-*.html` glob (note the hyphen) matches side-cars only.
- **`PHASE-MACHINE.md`** `done` row + Notes record that `done` is reached via `continue`, so anything that must run at `done` belongs in `continue/SKILL.md`, not just the `memo` phase files (the gotcha that caused this bug).
- **Added `artificialintelligenceact.eu`** to the WebFetch auto-approve allowlist (a recurring AI Act article/timeline reference). Law-firm blogs (e.g. `gibsondunn.com`) remain deliberately excluded — users grant those via the README `~/.claude/settings.json` fallback.

### Tests
171 pass (161 baseline + 10 tidy). WebFetch hook verified out-of-band against the shipped command string (native `WebFetch` + `mcp__workspace__web_fetch` + alt-key + allowlist-boundary cases all correct).

---

## 1.1.0 — 2026-05-29 (pipeline wall-clock optimization: run analyzer · SKILL.md router · revision-loop convergence · proportional follow-up)

**Targets the 1.5h–3h same-prompt variance in Full-mode runs.** Root cause (proven from the 2026-05-28 ~4h run `memo-20260528T072015Z-gdpr-ai-support-transcripts`): on the long autonomous block, Cowork context-summarization made the orchestrator drop instructions — reviewers dispatched **serially instead of in parallel (~40 min lost)**, the revision loop thrashed (scores 81.8→87.2→86.0, iteration 3 wasted), and `events.jsonl` went dark ~1h45m before the run finished. This release attacks that structurally and trims wasted work, with **no change to memo legal quality**.

### Added
- **`scripts/analyze_run.py`** (+ `scripts/tests/test_analyze_run.py`) — read-only forensics over a task's `events.jsonl` + file mtimes: per-phase / per-agent timing, **serial-reviewer-round detection**, score-regression flags, events-truncation detection, and `--compare <slow> <fast>`. Reconstructs the second half of a run from mtimes when the audit log dies mid-run (the common slow-run signature).
- **`skills/memo/PHASE-MACHINE.md`** — compact control-flow cheat-sheet (one row per `current_phase`: dispatch incl. **parallelism**, state writes, events, turn). Re-read at every phase boundary as a summarization defense; authoritative for control flow.
- **`scripts/tests/test_phase_machine_coverage.py`** — drift guard (cheat-sheet ↔ `PHASES_ORDERED` ↔ router ↔ phase files).

### Changed
- **B1 — `SKILL.md` is now a ~140-line router.** Its ~1,400 lines of per-phase prose were extracted verbatim (byte-verified lossless) into **`skills/memo/references/phases/phase-*.md`** (17 files), read only on entering each phase. The resident orchestrator instruction floor drops **~79K → ~17–25K tokens**, so context-summarization fires later / less destructively and the parallel-dispatch + event-emission invariants survive. `references/INDEX.md` demotes the progress/events/live-progress contracts to demand-read; `skills/continue/SKILL.md` gets a phase-reference mapping note.
- **C1 — revision-loop convergence.** The mediator records `aggregate_score` per iteration and: on a **regression** delivers the best earlier draft (instead of shipping a worse one), and on a **plateau** above the (revived) `exit_threshold_score` exits early as `accepted_early_on_v<N>`. Reuses existing validated `final_status` values — no schema break.
- **C2 — targeted revision edits.** The orchestrator pre-seeds `drafts/v<N+1>.md` as a copy of v<N>; the writer **edits only the mediator-flagged sections in place** (full rewrite only if blockers span >half the analytical sections). Prevents regressions in clean sections and cuts rewrite time.
- **D — proportional research follow-up.** Only `missing`-status gaps re-dispatch their named researcher; `weak` / informational gaps are disclosed as `drafting_warnings[]` instead of triggering a full 3-researcher re-run (~20 min when it would have fired).

### Fixed
- `references/pipeline-contract.md` §Tool inheritance now lists `Bash` + `mcp__cowork__update_artifact` for memo-writer / revision-mediator (matches their frontmatter; resolves the earlier live-progress "Bash not in allowlist" log lines).
- Stale post-refactor references repointed to phase files (`SKILL.md:186`, `Phase 2a line 296`, broken `(.)` links); `operating-contract.md` revision-cap matrix corrected from the obsolete Quick/Standard/Deep to **Brief=1, Full=3**.

### Tests
161 pass (149 baseline + 6 analyzer + 3 phase-machine coverage). C1 convergence exit states verified against `validate_state.py` (regression-revert + plateau both validate clean).

### Not in this release
B2 enforcement hooks (Stop + PreToolUse) remain **spike-gated** — they need a live-Cowork spike to confirm Stop re-entry + PreToolUse `deny` on Windows before shipping. No `git tag` was cut for this build (test build).

---

## 1.0.0 — 2026-05-28 (first public release — Lessons Studio removed, README rewritten for GitHub)

**This is the first public release of `memoforge`.** Two large changes land together: the Lessons Studio (cross-run learning) subsystem is removed from the plugin, and `README.md` is rewritten from scratch as a GitHub landing page for end users (lawyers, lay readers) rather than the prior engineering-internal layout.

### Lessons Studio removal

Phase 11.5 (post-export `lessons-extractor` dispatch), Phase 1.4 (advisory read of `learned-patterns.md`), the `/memoforge:lessons` Studio skill, pill #13 *Lessons* in the live-progress dashboard, the `lessons_extraction` state-machine phase, and the two telemetry events `phase_11_5_attempted` + `lessons_extracted` are all gone. The remaining pipeline is the v0.6.x shape (intake → planning → research → drafting → revision → polish → export → done) with all post-v0.6.x dashboard, visualize-widget, and state-validation infrastructure intact.

### Why

The Lessons Studio kept being silently skipped on long-running Full-mode tasks. The safeguards lived inside `skills/memo/SKILL.md` prose:

- v0.7.0 introduced the system end-to-end.
- v0.8.0 added a Studio visualize widget + monthly archive rollover.
- v0.8.1 added a `phase_11_5_attempted` sentinel + "DO NOT end the turn here" callout, so a missed Phase 11.5 would be visible in `events.jsonl`.
- v0.8.2 deferred the `phase_transition → done` event into Phase 11.5's tail and added a visible pill #13 *Lessons* to the live-progress dashboard, so users would notice if the pill never lit up.

In the 2026-05-28 production run (`memo-20260528T072015Z-gdpr-ai-support-transcripts`, ~4 hours wall-clock) all three v0.8.x safeguards failed simultaneously: `events.jsonl` stopped being emitted entirely after event #31 (~2h into the run), the live-progress timeline went `client_readiness → export → done` with NO `lessons_extraction` entry, `~/.claude/plugin-data/memoforge/` was never created, and the renderer cosmetically marked pill #13 *Lessons* as completed (a separate bug, only because the renderer treated terminal `done` as "all earlier phases must be completed" without checking the timeline). The root cause is that Cowork's context summarization compresses SKILL.md prose during long runs — by the time Phase 11 finishes, the explicit "emit sentinel FIRST" and "DO NOT end turn" instructions are no longer in active context. Spec-strength escalations have reached diminishing returns.

The system is being cut rather than patched further; any future re-introduction needs a non-prompt-resident enforcement mechanism (Stop hook, harness-level guard) instead of more SKILL.md prose.

### Removed (entire subsystem)

- `agents/lessons-extractor.md` — the two-pass cross-run learning subagent.
- `skills/lessons/` — the `/memoforge:lessons` Studio skill (interactive batch-review + `summary` / `stats` / `rollback` sub-commands).
- `scripts/resolve_lessons_home.py` — `LESSONS_HOME` path resolver.
- `skills/memo/SKILL.md` — Phase 1.4 (Read learned patterns), Phase 11.5 (entire phase including sentinel, dispatch, close-out), the "DO NOT end the turn here" callout at end of Phase 11, the Phase 12 conditional "💡 N new lessons proposed" appendix line, and the inline edits in Phase 11 that targeted `lessons_extraction` instead of `done`.
- `skills/memo/state-schema.md` — `lessons_extraction` enum value and explanation paragraph; `final_docx_path` predicate restored to `current_phase == "done"` only.
- `skills/memo/references/events-contract.md` — §"Tier 2 — Cross-run learning events" (sentinel + `lessons_extracted` schemas, triage matrix, examples) and §"Tier 2 — Lessons Studio events" (`visualize_*` events for the Studio's own `events.jsonl`).
- `skills/memo/references/widget-schemas.md` — §"Lessons Studio summary" and §"Lessons Studio statistics" widget data-payload sections plus the two corresponding top-table rows and the preface clause about the Studio-local precheck cache.
- `skills/memo/references/live-progress-contract.md` — `lessons-extractor` chip row + budget sentence + "Lessons-extractor specifics" paragraph.
- `skills/memo/references/pipeline-contract.md` — `lessons_extraction` row in the phase matrix; cell modifications in the `export` and `done` rows.
- `skills/memo/references/logging-contract.md` — lessons-extractor references in the Tier 1 vs Tier 2 motivation paragraphs.
- `skills/continue/SKILL.md` — resume-after-export note about Phase 11.5 being skipped on recovery.
- `scripts/validate_state.py` — `lessons_extraction` from `PHASES_ORDERED`; `final_docx_path` predicate scoped to `done` only.
- `scripts/render_live_progress.py` — pill #13 *Lessons* entry from PHASES list (total goes 14 → 13); *Summary* renumbered to id 13.
- `scripts/tests/test_validate_state.py` — `test_lessons_extraction_happy_path`, `test_lessons_extraction_without_final_docx_path_rejected`.
- `scripts/tests/test_render_live_progress.py` — `test_lessons_extraction_phase_maps_to_pill_13`; pill-count assertions updated 14 → 13.
- `lib/docx-render/README.md` — Phase 11 transition wording updated to `done`.
- `README.md` — §"Cross-run learning — the Lessons Studio (v0.7.0+)" entirely (~85 lines including the plugin-data layout tree). See §"README rewrite" below for the full new structure.
- `.claude-plugin/plugin.json` — `"and cross-run learning via the Lessons Studio"` clause dropped from `description`; `version` bumped to `1.0.0`.

### Preserved

- **All CHANGELOG history.** Entries for v0.7.0, v0.7.1, v0.7.2, v0.8.0, v0.8.1, v0.8.2 stay intact as historical record — CHANGELOG.md is not auto-loaded into orchestrator context.
- **All Lessons Studio source code.** Copied verbatim into `../attic-lessons-studio/v0.8.2/` (sibling of `memoforge/`, OUTSIDE the plugin tree so Cowork's plugin loader does not index it). Includes original `.md` and `.py` files plus extracted SKILL.md/references fragments and a plain-text `README.txt` documenting the snapshot and restore recipe.
- **All v0.7.x and v0.8.x dist zips.** `dist/memoforge-0.7.0.zip` through `dist/memoforge-0.8.2.zip` remain on disk as recovery points.
- **Plugin-data dir.** Users who already have `~/.claude/plugin-data/memoforge/` from prior v0.7.x / v0.8.x runs can keep it — v1.0.0 does not read or write it. Delete manually if you want to reclaim the disk space.

### README rewrite

`README.md` is fully rewritten for GitHub presentation, ~165 lines (vs ~390 in v0.8.2). The new structure targets a non-developer audience (lawyers, lay readers evaluating whether the plugin fits their workflow):

1. Hero with project name, one-line tagline, three static badges (version, license, "built for Cowork")
2. **What it does** — narrative on the multi-agent pipeline in plain English
3. **What you get** — five concrete outcomes (docx memo, source pack, reviewer findings, honest verdict, audit trail)
4. **Quick start** — three-step install + connect + ask flow with real example queries
5. **How it works** — short narrative + ASCII pipeline diagram + Brief vs Full mode comparison
6. **What you'll see along the way** — the four user-facing checkpoints walked through
7. **Customization** — Style Studio + output folder resolution
8. **What it won't do** — four honest limitations
9. **Privacy and data** — explicit statement that everything stays on the user's machine
10. **Going deeper** — pointers to `skills/memo/references/` and `CHANGELOG.md` for the technically curious
11. **License + contact**

Removed from the README (canonical content lives in `skills/memo/references/` and remains authoritative): the phase-by-phase pipeline walkthrough, the agent-by-agent breakdown, the MCP / WebSearch policy expansion, the live-progress dashboard internals, the always-deliver invariant section, the full repo layout tree.

### Test results

149 tests pass (+ 28 subtests) after removal — same count as v0.8.2 minus the three deleted lessons tests.

### Recovery recipe (for the removed Lessons Studio)

Two equivalent paths:

1. `cp -r ../attic-lessons-studio/v0.8.2/{agents,skills,scripts}/* memoforge/{agents,skills,scripts}/` + re-apply the surgical edits documented in `attic-lessons-studio/v0.8.2/skills/memo/SKILL-fragments.md` and the `references-fragments/*.md` files.
2. `git show <pre-removal-commit>:<path> > <path>` per-file, or `git checkout <pre-removal-commit> -- <paths>`.

### File map

`memoforge/.claude-plugin/plugin.json` · `memoforge/CHANGELOG.md` · `memoforge/README.md` · `memoforge/lib/docx-render/README.md` · `memoforge/scripts/render_live_progress.py` · `memoforge/scripts/validate_state.py` · `memoforge/scripts/tests/test_render_live_progress.py` · `memoforge/scripts/tests/test_validate_state.py` · `memoforge/skills/continue/SKILL.md` · `memoforge/skills/memo/SKILL.md` · `memoforge/skills/memo/state-schema.md` · `memoforge/skills/memo/references/events-contract.md` · `memoforge/skills/memo/references/live-progress-contract.md` · `memoforge/skills/memo/references/logging-contract.md` · `memoforge/skills/memo/references/pipeline-contract.md` · `memoforge/skills/memo/references/widget-schemas.md`

Deleted: `memoforge/agents/lessons-extractor.md` · `memoforge/skills/lessons/SKILL.md` · `memoforge/scripts/resolve_lessons_home.py`

### Release note

An internal `memoforge-0.9.0.zip` was built during development of this release but never published — `1.0.0` is the first tag and the first published artifact. The GitHub repository was renamed from `legal-memo-writer` to `memoforge` as part of this release.

---

## Project arc — live-progress dashboard, shipped (v0.2.0 → v0.6.2)

> Reference summary for the multi-week arc that turned the plugin's silent 5–40-minute autonomous blocks into a continuous, real-time sidebar dashboard. The system now works end-to-end in production Cowork on Windows: artifact mints on Phase 1, refreshes in real time as subagents work, ticks elapsed-time counters every second via JS, and never surfaces a permission prompt to the user.

### The problem (May 2026)

The `/memoforge:memo` pipeline runs a 15-agent legal memorandum production line. Phases 5→7.5 (parallel research → sufficiency → currency → source-pack → checkpoint) and Phases 8→12 (drafting → revision loop → polish → export) each spend 5–40 minutes in a single autonomous turn during which Cowork's chat surface flushes nothing — the user sees `Agent` dispatch tiles + a side-panel TodoWrite but no text. Closed GitHub issues #26805, #29773, #29547, #33564, #44776 establish the chat-buffering bug as a hard upstream constraint with no fix planned by Anthropic.

### What we tried, and what worked

| Attempt | Hypothesis | Outcome |
|---|---|---|
| **v0.2.0** | Orchestrator-side `mcp__cowork__update_artifact` calls bypass the chat-buffering bug. | **Falsified.** Real-run on 2026-05-24 showed both the chat indicator strips AND the sidebar card buffer to end-of-turn — same failure mode as text. Rolled back to v0.1.1. Full forensics in `docs/postmortems/v0.2.0-live-progress.md`. |
| **v0.5.0-probe** | Subagent-side `update_artifact` calls bypass the parent-orchestrator buffer (postmortem §9 open hypothesis). | **STREAMING PASS.** Empirically confirmed 2026-05-25 with a one-subagent probe + 25-second sleeps + falsifiable framing. User verbatim: *"Это работает, обновляется в режиме реального времени артефакт, это удобно и классно выглядит."* |
| **v0.5.0** | Productionise the §9 mechanic across all 15 agents. | Shipped: master artifact minted at Phase 1, every heavy/medium subagent calls `update_artifact` at its internal step boundaries. ~50 update_artifact calls per Full-mode run. |
| **v0.5.1** | Subagents sometimes skip the `done` emission while forming their return summary. | Added Pre-return checklist section before every `## Final response` in all 15 instrumented agents. Forces explicit STOP-and-verify. |
| **v0.5.2 → v0.5.4** | Cowork prompts on every subagent's update_artifact call ("always allow" doesn't persist across subagent dispatches per #24433). Tried plugin-bundled `settings.json` and `PreToolUse` hook to pre-grant. | Two false starts: plugin `settings.json` only honors `agent` and `subagentStatusLine` keys per docs (permissions silently dropped); hook command `${CLAUDE_PLUGIN_ROOT}` env var didn't expand in Cowork's hook executor on Windows. **v0.5.4 fixed the hook with the docs-correct quoting**, then **v0.5.7 ditched the env var entirely with an inline `python3 -c "..."` command** — works in production. |
| **v0.5.5 → v0.5.6** | Orchestrator was skipping the artifact mint at Phase 1 step 3.5 because step 4 (fact-assumption-analyst dispatch) opening said "after all THREE preceding steps" without naming the mint. | **v0.5.6 moved the mint into Step 1 sub-step 1d** (non-skippable task setup). Verified empirically that the mint now happens. |
| **v0.5.7** | Hook command `${CLAUDE_PLUGIN_ROOT}` wasn't expanding in Cowork's Windows hook executor. | **Inline `python3 -c "..."`** with no env-var dependency. Hook auto-approves mcp__cowork__* artifact tools so the user sees zero permission prompts. |
| **v0.6.0** | Dashboard is functional but ugly and informationless. | Flat-design HTML refresh + inline `<script>` block (≤30 lines) for self-contained ticking timers + three info chips (source counts, active subagent, iteration counter) + denser update_artifact emissions (memo-writer per-section, mediator per-reviewer). +50 % update frequency in Full mode. |
| **v0.6.1** | Phase pills numbered "1, 1.5, 2a, 3, 4, …" with Mode rendering before Intake — confusing and didn't match execution order. | Renumbered to clean sequential 1–13; reordered so Mode comes after Intake. State schema unchanged. |
| **v0.6.2** | Header truncated raw user query mid-sentence; parallel dispatches collapsed into "🛠 3 researchers (parallel)". | Added `live_progress.topic` (3–7 word theme generated at Step 1d) for the header. Changed `active_subagent` (string) → `active_subagents` (list) so parallel batches show one chip per subagent. |

### Where the system stands at v0.6.2

- **Live dashboard appears immediately** after Phase 1 setup with the new flat design.
- **Real-time JS tickers** update elapsed-in-phase, total elapsed, and "Updated Xs ago" every second without `update_artifact` traffic.
- **Three info chips** surface contextually: `📊 N statutes · M cases · K doctrine` (after Phase 7), `🛠 <subagent-name>` (one per active subagent), `🔁 iteration N of max` (during revision loop).
- **Per-subagent chips** for parallel dispatches (Phase 5 research, Phase 9 reviewers) show each name side-by-side, not a collapsed label.
- **Sequential 1–13 phase pills** in actual execution order (Init → Intake → Mode → Plan → Approve → Research → Sufficiency → Source-pack → Draft v1 → Revise → Polish → Export → Summary).
- **Clean topic header** instead of truncated raw query.
- **~75 update_artifact calls per Full-mode run** (was ~50 in v0.5.0; +50 %): memo-writer per-section, mediator per-reviewer, plus all the v0.5.0 baseline points.
- **Zero permission prompts** in production — plugin-bundled inline-Python hook auto-approves the three cowork artifact tools without env-var dependency.
- **Substantive memo output unchanged** from v0.4.0 — all live-progress work is supplementary visual instrumentation, never on the critical path.

### Reusable findings for future plugins

Documented empirically through this arc (also in `~/.claude/projects/.../memory/reference_cowork_live_progress.md` for cross-session memory):

1. **`mcp__cowork__update_artifact` from a subagent flushes real-time to the parent's chat scroll.** Orchestrator-side calls buffer to end-of-turn. The subagent surface is the streaming hatch.
2. **Plugin-bundled `settings.json` only honors `agent` and `subagentStatusLine` keys** per Anthropic docs — permission rules there are silently dropped. Permissions must come from user/project/managed settings OR a `PreToolUse` hook.
3. **`${CLAUDE_PLUGIN_ROOT}` does NOT expand in Cowork's hook command executor on Windows** (literal string is passed through). Use inline `python3 -c "..."` commands or absolute paths instead. Empirically falsified the docs example.
4. **AskUserQuestion silent-fails post-single-Task-dispatch** in plugin-skill context (stronger than the v0.0.43 "post-parallel" finding). Use text-parsed gates for any user gate after any subagent dispatch.
5. **Cowork's "Always allow" UI doesn't persist across subagent dispatch boundaries** ([#24433](https://github.com/anthropics/claude-code/issues/24433)). Plugin-bundled `PreToolUse` hook is the only programmatic bypass.
6. **CSS-only animations + inline `<script>` blocks work in cowork artifact iframes.** Setting `setInterval` for tickers does not require a callback to the harness; the iframe sandbox allows self-contained DOM mutation.
7. **Instruction-following discipline matters more than instruction count.** The Pre-return checklist pattern (STOP-and-verify section immediately before `## Final response`) reliably catches the LLM at the moment it would normally skip a "best-effort" emission. Used in 15 agents; closes the gap that v0.5.0 had with orchestrator emissions falling silent.

### Reference artifacts

- Renderer: `scripts/render_live_progress.py` (54 unit tests in `scripts/tests/test_render_live_progress.py`).
- Contract: `skills/memo/references/live-progress-contract.md`.
- Orchestrator mantras: `skills/memo/SKILL.md` Step 1 sub-step 1d (mint) and §"MANDATORY — orchestrator's active_subagents plumbing" (per-dispatch).
- 15 instrumented agents: every file under `agents/*.md` except `style-extractor.md` (which is Style-Studio-only, not in the main pipeline) has a `## Live progress` section + `## Pre-return checklist`.
- Initial postmortem (still required reading for context): `docs/postmortems/v0.2.0-live-progress.md`.
- The diagnostic probe that proved §9: `dist/memoforge-0.5.0-probe.zip` (archived on disk; never republished).

---

## 0.8.2 — 2026-05-27 (lessons-extractor path fix + visible Phase 11.5 pill)

**Two regressions surfaced by user testing of v0.8.1:**

1. **Wrong plugin-data path on Windows.** The lessons-extractor wrote signal/lesson files into `<task_work_dir>/plugin-data/...` instead of `~/.claude/plugin-data/memoforge/`. Both the orchestrator and the agent computed `LESSONS_HOME` via the bash expansion `${MEMOFORGE_LESSONS_HOME:-$HOME/.claude/plugin-data/memoforge}`; in Cowork's plugin-skill bash on Windows `$HOME` was empty, so the expansion collapsed to a relative path that resolved against cwd. The Lessons Studio (`/memoforge:lessons`) used the same expansion but happened to run in a context where `$HOME` was set — so it scanned the right path, found nothing, and printed the "No lessons yet" empty-state even though signals had been written elsewhere.

2. **Phase 11.5 was invisible during its 4–5 minute window.** After Phase 11 set `current_phase = done` and the docx artifact card rendered, the live-progress dashboard sat on pill #13 *Summary* with no visible difference between "still extracting lessons" and "task complete." Users switched tabs prematurely.

### Path fix — Python-resolved canonical root

- New `scripts/resolve_lessons_home.py`: honors `$MEMOFORGE_LESSONS_HOME` if set, else returns `str(Path.home() / ".claude" / "plugin-data" / "memoforge")`. `Path.home()` reads `%USERPROFILE%` on Windows and `$HOME` on Unix — reliable across shells (Cowork plugin-skill bash, PowerShell, cmd, Git Bash). Verified to return the canonical absolute path even when bash `$HOME=""`.
- Three call sites swap to the helper: `skills/memo/SKILL.md` Phase 11.5 §"Resolve lessons home"; `skills/lessons/SKILL.md` §"Resolve plugin-data paths"; the lessons-extractor agent reads `lessons_home` from its prompt verbatim (orchestrator already passed it) instead of recomputing.
- The lessons-extractor `Inputs` section now hard-requires `lessons_home` from the dispatch prompt; missing → `Status: extraction_failed:missing_lessons_home_param` rather than guessing.

### Visible Phase 11.5 — new pill #13 *Lessons*

- `scripts/render_live_progress.py` PHASES list grows from 13 to 14 entries: pill #13 *Lessons* (state_phase `lessons_extraction`), pill #14 *Summary* (state_phases `done | failed | cancelled_by_user`).
- Phase 11 in `memo/SKILL.md` now transitions `export → lessons_extraction` (instead of `export → done`). Phase 11.5 close-out emits the final `lessons_extraction → done` transition after the lessons-extractor returns. Timeline entries open and close around the new phase so the dashboard's elapsed-time ticker advances against pill #13 throughout extraction.
- `lessons-extractor` agent gains four `update_artifact` emissions at internal step boundaries (`lessons-pass1-start`, `lessons-pass2-start`, `lessons-finalising`, `lessons-done`) — best-effort, flag-gated, wrapped in `|| true`. Pill #13 thus shows a live-ticking counter for the whole 4–5 minute window, not a frozen Summary pill.
- `state-schema.md` `current_phase` enum gains `"lessons_extraction"`. `scripts/validate_state.py` PHASES_ORDERED inserts the new phase between `export` and `done`; `final_docx_path` predicate now covers both `lessons_extraction` and `done` (docx is on disk before the transition).
- `skills/continue/SKILL.md` documents that the resume-after-export path jumps straight to `done` (skipping Phase 11.5) — partial-failure recovery never retroactively extracts lessons.

### Doc + test updates

- `pipeline-contract.md`, `events-contract.md`, `live-progress-contract.md`, `lib/docx-render/README.md` and `state-schema.md` updated for the new transition order and pill count.
- Tests: 5 hardcoded `"13"` → `"14"` in `test_render_live_progress.py`; new `test_lessons_extraction_phase_maps_to_pill_13`. New `test_lessons_extraction_happy_path` and `test_lessons_extraction_without_final_docx_path_rejected` in `test_validate_state.py`. Full suite: 152 passed + 29 subtests.

### File map

- `memoforge/scripts/resolve_lessons_home.py` (new)
- `memoforge/scripts/render_live_progress.py` (PHASES list)
- `memoforge/scripts/validate_state.py` (PHASES_ORDERED + final_docx_path predicate)
- `memoforge/scripts/tests/test_render_live_progress.py`, `test_validate_state.py`
- `memoforge/agents/lessons-extractor.md` (Inputs, Live progress, Pre-return checklist, Failure mode)
- `memoforge/skills/memo/SKILL.md` (Phase 11 transition, Phase 11.5 path resolution + close-out, Mantras prose)
- `memoforge/skills/lessons/SKILL.md` (path resolution)
- `memoforge/skills/memo/state-schema.md` (current_phase enum)
- `memoforge/skills/memo/references/events-contract.md`, `pipeline-contract.md`, `live-progress-contract.md`
- `memoforge/skills/continue/SKILL.md` (resume-after-export note)
- `memoforge/lib/docx-render/README.md`
- `memoforge/.claude-plugin/plugin.json` (version 0.8.1 → 0.8.2)

---

## 0.8.1 — 2026-05-27 (Phase 11.5 sentinel event + DO-NOT-end-turn guard at Phase 11 boundary)

**Forensics on the v0.8.0 GDPR/AI-Act test run revealed Phase 11.5 (lessons extraction) was silently skipped — no `agent_dispatched` for `lessons-extractor`, no `lessons_extracted` event, and `~/.claude/plugin-data/memoforge/` was never created. The skip was indistinguishable from a silent failure inside the extractor: both leave `events.jsonl` ending at Phase 11's `phase_transition → done`. This release adds a sentinel event that disambiguates the two cases and a structural guard at the Phase 11 boundary that makes the skip much harder.**

### Why

Phase 11 writes `current_phase = done` AND emits the `phase_transition → done` event AS ITS FINAL STEP, BEFORE Phase 11.5 has even started. From the orchestrator's perspective the run looks "done" at that point, and Phase 11.5 (best-effort, no TodoWrite item by design, no own state flag) is easy to skim past. SKILL.md spec for Phase 11.5 was complete and unambiguous, but provided no signal in `events.jsonl` to tell — after the fact — whether the orchestrator at least *tried* to run it.

### What changed

- **New `phase_11_5_attempted` Tier-2 event** (registered in `references/events-contract.md`). Emitted as the VERY FIRST action of Phase 11.5 — before resolving `LESSONS_HOME`, before `active_subagents` plumbing, before agent dispatch. Pure observability sentinel, `data: {}`, wrapped in `|| true`. Pair with `lessons_extracted` for a 5-row triage matrix that distinguishes "Phase 11.5 healthy" / "extractor failed" / "dispatch chain broke silently" / "Phase 11.5 skipped entirely" / "schema violation".
- **`### DO NOT end the turn here (MANDATORY)` callout** added at the end of Phase 11 in `SKILL.md`, immediately before the Phase 11.5 header. Explicitly tells the orchestrator that `current_phase = done` after Phase 11 is a **docx-delivered flag**, not a **turn-end signal**, and names Phase 11.5 and Phase 12 as the remaining mandatory phases.
- **`### Emit phase_11_5_attempted sentinel FIRST`** subsection added at the start of Phase 11.5 (after the intro paragraphs, before "Resolve lessons home"). Inline `log_event.py` invocation with full `|| true` wrap and a complete triage table copied for the reader.

### What did NOT change

- Phase 11.5 remains best-effort. The sentinel does not block Phase 12 if it fails to emit — it is wrapped in `|| true` like every other Phase 11.5 emission.
- `current_phase = done` is still set in Phase 11 (not moved). The structural reinforcement is via the explicit "DO NOT end turn" callout, not via reordering state writes. If the sentinel-plus-guard approach is still insufficient empirically (next test run reveals skip continues), the v0.8.2 follow-up is to defer the `phase_transition → done` event from Phase 11 into Phase 11.5's tail.
- No state-schema change, no agent-spec change, no orchestrator-mantra change beyond the two text additions above.
- TodoWrite list stays at 14 items (the explicit non-extension reasoning in SKILL.md §"Mantras applied vs skipped" is unchanged — Phase 11.5 by design does not appear in the user-tracked pipeline list).

### Forensics — what tipped this off

- v0.8.0 production run `memo-20260527T073021Z-gdpr-ai-support-transcripts` (GDPR / AI-Act memo) completed end-to-end with `final_status: approved_on_v3` and a delivered docx. Substance approved (logic 96, citations 94, counterarguments 94).
- BUT: `events.jsonl` ended at `phase_transition → done` (event #117, `reason: "docx_written"`). No `lessons-extractor` `agent_dispatched`, no `lessons_extracted`. `~/.claude/plugin-data/memoforge/` directory did not exist anywhere on the user's machine despite multiple prior production runs.
- Without the sentinel introduced here, "Phase 11.5 was reached but every emission inside it failed silently" was indistinguishable from "Phase 11.5 was never reached because the orchestrator misread `done` as a turn-end". Next test run with v0.8.1 will resolve the ambiguity in one line of `grep`.

### Test plan for v0.8.1

Run any Full-mode `/memoforge:memo` task. After the docx delivers:

```bash
grep '"event":"phase_11_5_attempted"\|"event":"lessons_extracted"' "$WORK_DIR/events.jsonl"
```

- **Both events present** → Phase 11.5 healthy; v0.8.1 working as intended; lessons accumulating in `~/.claude/plugin-data/memoforge/`.
- **Sentinel only** → Phase 11.5 reached but extractor failed silently after the sentinel; check `agent_dispatched` / `agent_returned` rows for `lessons-extractor` and the agent's tool logs.
- **Neither** → Sentinel itself was skipped; the structural guard at end-of-Phase-11 didn't bite. Escalate to v0.8.2 (defer Phase 11 `done` event into Phase 11.5's tail).

---

## 0.8.0 — 2026-05-27 (Phase 3 polish: visualize widget for Lessons Studio + stats subcommand + monthly signal archive rollover)

**Closes the three remaining items from "Layer B — cross-run learning, v3" §"Implementation order — Phase 3 (Polish)" left as TODO in v0.7.0: a visualize widget for the Studio summary, a `stats` subcommand, and a monthly archive rollover for stale signals. No behavior change for any memo task itself; the lessons-extractor + Studio surface that v0.7.0 shipped as text-only now renders a data_viz widget in the sidebar when `visualize` is available, exposes a read-only `stats` aggregate, and trims the signals working set automatically once per calendar month.**

### Why

v0.7.0 shipped the cross-run learning system (Phase 1 telemetry + Phase 2 Studio + override reads) and the v0.7.0 CHANGELOG explicitly noted: *"No visualize widget for the Studio summary. v0.7.0 ships text-only Studio UI; visualize widget is Phase 3 polish."* Three concrete gaps remained from the v3 plan:

1. **No visual surface on the Studio.** The Studio's summary screen was a plain markdown bullet list rendered in chat. Cowork users have a sidebar dashboard for every other long-running surface (live-progress, Phase 1.5/2a/4a/6.6/12 widgets) — the Studio's batch-review experience is the one place that benefited most from a visual at-a-glance and didn't have one.
2. **No aggregate view.** `summary` is "since last visit" focused (great for incremental review); there was no command to see *all-time* aggregates (apply/reject ratios per tier, per-classification convergence, MCP health by tool, currency-stale top sources). Users wanting to evaluate "is this learning system actually helping?" had to read raw files.
3. **Signals accumulated indefinitely.** `agents/lessons-extractor.md` Pass 1 created `signals/archive/` via `mkdir -p` but never wrote to it. After 30 days a signal stops contributing to threshold counts (Pass 2 globs `signals/*.json` filtered by `observed_at >= now - 30d`) but its file lingered, eventually slowing the `glob+parse` step. Over many months the dir would grow unbounded.

### What changed

**Part A — Visualize widget for the Lessons Studio summary (`data_viz` module).**

- **`skills/memo/references/widget-schemas.md`** gains two new sections: §"Lessons Studio summary" (rendered by the interactive Studio at Step 1) and §"Lessons Studio statistics" (rendered by the new `stats` subcommand). Both use the cached `data_viz` module guidelines — same module Phase 12 Final dashboard uses — so no new `read_me` modules are required. Top widget-table updated with the two new rows. Snapshot paths live under `$LESSONS_HOME/widgets/lessons-studio-<unix_ts>.html` and `lessons-stats-<unix_ts>.html` respectively, NOT under `$WORK_DIR/widgets/` — the Studio runs outside any memo task and has no work_dir.
- **`skills/lessons/SKILL.md`** gains a new §"Visualize precheck (v0.8.0+)" section right after "Resolve plugin-data paths" that mirrors the memo-pipeline precheck pattern (`skills/memo/SKILL.md:325-347`) into a Studio-local cache: `$LESSONS_HOME/meta/visualize-precheck.json` (30-day TTL) + `$LESSONS_HOME/cache/visualize-guidelines.md` (one-shot `read_me` for `["data_viz"]`). New env vars `WIDGETS_DIR`, `VISUALIZE_PRECHECK`, `VISUALIZE_GUIDELINES_CACHE`, `STUDIO_EVENTS_LOG` added to the path-resolve block; bootstrap `mkdir -p` extended to create `widgets/` and `cache/`. Graceful fallback: if `enabled=false` or anything throws, Studio falls through to the original text-only summary.
- **§"Step 1 — Render summary screen" restructured into Path A (widget) / Path B (text fallback).** Path A builds the JSON payload (≤2 KB) from the corpus the Studio already scans, generates HTML ≤30 KB following the cached `data_viz` guidelines, atomic-writes the snapshot, calls `<namespace>__show_widget`, emits a `visualize_widget_rendered` event into `$STUDIO_EVENTS_LOG`, and prints a 6-line chat companion ("widget rendered in sidebar" + the 3 since-last-visit counters). Path B is the v0.7.x text summary unchanged. The §"Summary sub-command" picks the same A/B branch.
- **Hook `hooks/hooks.json` unchanged** — the v0.6.3 PreToolUse matcher `mcp__.*visualize.*__(show_widget|read_me)` already pre-approves the new Studio widget calls; no permission changes required.

**Part B — `stats` subcommand (`/memoforge:lessons stats`).**

- **`argument-hint`** extended: `[rollback <lesson_id> | summary | stats | (no args for interactive Studio)]`.
- **Parse `$ARGUMENTS`** branch added for `stats`; unknown-action error message updated to mention the new subcommand.
- **New §"Stats sub-command"** section between §"Summary sub-command" and §"Exit and update last_review.json". Builds the extended payload per `widget-schemas.md §"Lessons Studio statistics"` (≤4 KB JSON — adds `apply_reject_ratio` per Tier 2/3, full `convergence_by_type` from `learned-patterns.md` § Convergence statistics, full `mcp_health` table, and `currency_stale_top3`). Read-only: does NOT touch `meta/last_review.json` (same contract as `summary`). When visualize is enabled, renders Path A widget AND prints the full text tables as a companion (stats screenshots benefit from preserving the numbers in chat); when disabled, prints Path B alone.

**Part C — Monthly archive rollover for old signals.**

- **`agents/lessons-extractor.md`** Pass 1 init gains a new §"Monthly archive rollover (v0.8.0+)" block AFTER the existing `mkdir -p` step and BEFORE the §"What you read" section. A marker file `$SIGNALS_DIR/archive/.last-archive-yyyymm` (single line containing the YYYY-MM of the last sweep) gates the block — it's a no-op except on the first dispatch of each calendar month. The sweep parses `observed_at` from each `signals/*.json` with a small embedded Python (deterministic JSON layout; falls back to skipping malformed files), moves anything older than 30 days into `signals/archive/<YYYY-MM-of-observed_at>/`, captures the count in `ARCHIVE_MOVED`. Wrapped in `|| true` per the agent's existing best-effort discipline. Pass 2 corpus glob is unchanged — already explicitly `glob $SIGNALS_DIR/*.json (NOT archive/)` (line 168 in v0.7.2; verified, no edit needed) — archived signals never re-enter threshold counts.
- **Final response template** gets a new optional line `Archive rollover: <N> signals moved to archive/<YYYY-MM>/` emitted only when N>0. Counter definitions section documents `A` (`archive_moved`); orchestrator's parser (in `skills/memo/SKILL.md`) gets `A = <int after "Archive rollover: ">` added to the parse list and `archive_moved` added to the `lessons_extracted` event's `data` payload.
- **`skills/memo/references/events-contract.md` §"lessons_extracted"** schema gains the `archive_moved` field with explanatory comment; example success entry updated to include `archive_moved: 0`; a new "first-of-month entry" example added showing `archive_moved: 47`. Failure entry example also updated. The orchestrator's parser tolerates the field being absent (defaults to 0) for backward-compat with v0.7.x agent versions that might still be in flight during the upgrade.

**Part D — Cross-cutting cleanup.**

- **`skills/lessons/SKILL.md`** §"Exit and update last_review.json" template bumps hard-coded `session_version: "0.7.0"` → `"0.8.0"`. Convention going forward: bump this in lockstep with `plugin.json.version` whenever Studio behavior changes.
- **`README.md`** — version badge `0.7.2 → 0.8.0`, install line `memoforge-0.7.2.zip → memoforge-0.8.0.zip`, §"Invoke the Studio" gains the `/memoforge:lessons stats` command and a new "v0.8.0 additions" paragraph documenting the widget rendering + archive rollover.
- **`.claude-plugin/plugin.json`** version → `0.8.0`.

### Out of scope (deferred)

- **Standalone `scripts/rotate_signal_archive.py` + `/memoforge:lessons archive` subcommand** for manual recovery — the auto-rollover in lessons-extractor covers the steady-state need. A manual subcommand can be added in a future patch if recovery scenarios surface (signal corpus corruption, restoring from backup, etc.).
- **Interactive Apply/Reject inside the widget** — widgets carry no JavaScript callbacks per the existing `widget-schemas.md` contract. Decisions stay in `AskUserQuestion` for v0.8.0.
- **Cross-machine sync of plugin-data**, **LLM-judged auto-grading of applied lessons**, **`unreject` action** — all listed as Out of Scope in the v3 plan; unchanged here.

### Tests

No new Python code. The existing 137-test suite passes unchanged. Verification is manual per the v3 plan §"Verification" — visualize precheck cache regeneration, widget renders, graceful fallback when disabled, `stats` doesn't touch `last_review.json`, monthly archive rollover triggers exactly once per calendar month and moves only signals older than 30 days, Pass 2 corpus excludes the archive subtree.

### Effect on users

- **First Studio visit after v0.8.0 install with `visualize` enabled** → sidebar widget appears alongside the chat companion. No interaction change — Apply/Reject still happens through the existing `AskUserQuestion` menu.
- **First Studio visit without `visualize`** → identical behavior to v0.7.x (text-only summary). Graceful fallback contract preserved.
- **First memo task of a new calendar month** → the Phase 11.5 lessons-extractor dispatch may take a fraction longer (one filesystem walk + moves) and the `lessons_extracted` event records `archive_moved: N` for visibility. Steady-state runs the rest of the month are unaffected.
- **Anyone running `/memoforge:lessons stats`** → new aggregate view; safe to call any time without consuming the since-last-visit window.

### Manifest match

`.claude-plugin/plugin.json (0.8.0) === README badge (0.8.0) === README install line (memoforge-0.8.0.zip) === CHANGELOG top entry (0.8.0) === dist/memoforge-0.8.0.zip`.

## 0.7.2 — 2026-05-26 (remove side-car artifact escape hatch from HARD RULE)

**Tightens the v0.7.1 HARD RULE on `live-progress.html` ownership. v0.7.1 sanctioned a side-car artifact alternative ("if you genuinely need a one-off rich view, mint a SEPARATE artifact with a different id") — v0.7.2 explicitly REMOVES that escape hatch. The master `memo-<task_id>-live` is the sole Cowork artifact the pipeline maintains. There are no exceptions.**

### Why

v0.7.1's HARD RULE blocked the most common orchestrator misbehavior (overwriting `live-progress.html` with custom inline HTML), but it left a documented loophole: mint a side-car artifact via `mcp__cowork__create_artifact` with a different id. User flagged this as a back door immediately after v0.7.1 commit — the same context-pressure that drives orchestrators to overwrite the master file would also drive them to mint side-cars. Reasons documented in the contract:

- Multiple artifacts in the sidebar are visual chaos, not richer information — each card competes for attention, no canonical reading order.
- Side-cars bypass the same tests / schema / backward-compat protections as inline writes. The only difference is the file landing in a different artifact id slot rather than overwriting the master file.
- The plugin hook auto-approves `mcp__cowork__create_artifact` for ANY id (matcher is tool-name-only, not argument-aware). Side-cars would proliferate without permission prompts to alert the user that the orchestrator is going off-script.
- "Side-car for one-off rich view" is improvisation by another name. The discipline must be: the renderer's output IS the dashboard, no exceptions.

### What changed

- **`skills/memo/references/live-progress-contract.md` §"HARD RULE" / §"What to do INSTEAD"** — the third bullet ("Want a one-off rich view at a specific moment? Use `mcp__cowork__create_artifact` to mint a SEPARATE artifact...") is REMOVED. Replaced with a new "Side-car artifacts are NOT a sanctioned escape hatch (v0.7.2+)" block that explicitly enumerates the four reasons side-cars are forbidden and clarifies that "feature request for a future plugin version" is the right response when the standard renderer feels insufficient. The two remaining sanctioned paths (edit renderer; add new field under live_progress) are unchanged. New closing sentence: "The master `memo-<task_id>-live` artifact is the **sole** Cowork artifact the pipeline mints under `mcp__cowork__create_artifact`."
- **`skills/memo/SKILL.md` Step 1 sub-action 1d-3 STOP-block** — extended to explicitly prohibit side-car mints alongside direct file writes: "Do NOT mint side-car artifacts via `mcp__cowork__create_artifact` with a non-master id (e.g. `memo-<task_id>-research-snapshot`) — v0.7.2 explicitly REMOVED the side-car escape hatch that v0.7.1 had inadvertently sanctioned. The master `memo-<task_id>-live` is the sole Cowork artifact the pipeline mints; this Step 1d call is the one permitted `create_artifact` invocation per task."
- **`skills/memo/SKILL.md` downstream-responsibility STOP-block** — extended analogously: phase-transition refreshes go through `update_artifact` on the master id, never `create_artifact` on a new id.

### Enforcement layers (unchanged from v0.7.1, scope-locked at prose discipline)

v0.7.2 closes the documented loophole; it does NOT add a programmatic enforcement layer. The hook (`hooks/hooks.json`) still auto-approves `mcp__cowork__create_artifact` for any id — a future hardening could parse `tool_input.id` in the inline Python and only auto-approve when the id matches the master `memo-*-live` pattern, surfacing other ids as permission prompts to alert the user that the orchestrator is going off-script. That hook-argument-aware tightening is a v0.7.3+ candidate, NOT shipped here, to keep the v0.7.2 scope narrow (prose-only discipline change).

The `live_progress_html_overwrite_detected` mtime-check in the renderer (the other v0.7.1 §Enforcement posture future-candidate) likewise remains unimplemented in v0.7.2.

### Tests

No code changes. 137/137 tests pass unchanged.

### Effect on users

No user-visible behavior change for runs where the orchestrator was already following the v0.7.1 HARD RULE (i.e. going through the renderer at every refresh). The change is purely documentation tightening: future production runs in which an orchestrator was tempted by the v0.7.1 side-car loophole now have no sanctioned alternative — they must either ship the renderer extension first OR accept the standard dashboard output.

### Manifest match

`.claude-plugin/plugin.json (0.7.2) === README badge (0.7.2) === README install line (memoforge-0.7.2.zip) === CHANGELOG top entry (0.7.2) === dist/memoforge-0.7.2.zip`.

## 0.7.1 — 2026-05-26 (HARD RULE: live-progress.html owned by render_live_progress.py + fix research_sufficiency_followup_pending phase coverage)

**Two discipline + bug-fix items observed in v0.6.3 / v0.7.0 production runs.**

### Why

1. **Orchestrator improvisation on `live-progress.html`.** v0.6.x and v0.7.0 production runs showed orchestrators occasionally bypassing `scripts/render_live_progress.py` and writing custom HTML directly to `<work_dir>/live-progress.html` — typically after a heavy subagent (e.g. `case-law-researcher`) returned with rich `final_response_summary` data. The orchestrator would construct a research-phase-specific dashboard inline (DONE/RUNNING per-researcher badges, per-step citation lists) and call `mcp__cowork__update_artifact` with the overwritten file. Visually the result was sometimes nicer than the standard renderer, BUT: non-deterministic (re-runs differ), not data-driven (data isn't in state.json so the next render call wipes it), bypasses tests, bypasses schema, bypasses backward-compat. User confirmed it happened multiple times.

2. **Dashboard regression at `research_sufficiency_followup_pending`.** v0.6.3 added the new phase enum value but `scripts/render_live_progress.py` PHASES[6]("Sufficiency").state_phases was not extended to include it. Result: when the orchestrator passed `current_phase == "research_sufficiency_followup_pending"` to the renderer, `find_phase_index()` returned `None`, and every downstream rendering decision broke — all 13 phase pills greyed out, "0 of 13 phases complete" displayed even when 6 phases were actually done, hero showed `PHASE — · — · —`. The user-supplied `current_step` text rendered correctly (it's a string parameter, doesn't go through phase math), but the phase-position UI was useless. Caught and fixed during a live production run.

### What changed

**Part A — HARD RULE: `<work_dir>/live-progress.html` is owned by `render_live_progress.py`.**

- **`skills/memo/references/live-progress-contract.md`** gains a new H2 section "HARD RULE — `<work_dir>/live-progress.html` is owned by `render_live_progress.py` (v0.7.1+)" placed right after "How the channel works". The section documents the prohibition explicitly:
  - Orchestrator and every subagent MUST NOT `Write` / `Edit` `live-progress.html`, MUST NOT use Bash `cat`/`echo`/heredoc/`python3 -c` to emit HTML into the path, MUST NOT call `update_artifact` with an `html_path` pointing at a file NOT produced by the renderer.
  - The ONLY supported refresh sequence: update `state.json.live_progress.*` → run renderer → call `update_artifact`.
  - Rationale enumerated (non-determinism, not data-driven, bypasses tests, bypasses schema, bypasses backward-compat) with the v0.6.x improvisation pattern called out by name.
  - Three alternatives documented for when the standard dashboard feels insufficient: (a) extend renderer + tests + schema, (b) add new field under `live_progress`, (c) mint a SEPARATE side-car artifact with a different id via `mcp__cowork__create_artifact`. The hook auto-approves any `create_artifact`, so side-cars are permitted; the master `memo-<task_id>-live` artifact's html_path stays exclusive to the renderer.
  - Enforcement posture (instruction-following discipline + STOP-block reinforcements + future v0.7.2 candidate: mtime check in the renderer to log `live_progress_html_overwrite_detected` events post-hoc).

- **`skills/memo/SKILL.md` Step 1 sub-action 1d-3** (initial mint render) gains a STOP-block immediately above the render bash invocation pointing to the contract's HARD RULE section.

- **`skills/memo/SKILL.md` "downstream responsibility" block** (phase-transition re-render) gains an analogous STOP-block immediately above the 3-step transition sequence.

- **`skills/memo/references/live-progress-contract.md` "Canonical subagent update pattern"** section gets a one-sentence reinforcement that the renderer is the ONLY supported write path for subagents too (not just for the orchestrator).

**Part B — fix `research_sufficiency_followup_pending` phase coverage in renderer.**

- **`scripts/render_live_progress.py` PHASES[6].state_phases** extended from `["research_sufficiency", "currency_check"]` to `["research_sufficiency", "research_sufficiency_followup_pending", "currency_check"]`. The Phase 6.6 user-followup gate is logically a sub-state of "Sufficiency" review (it's the orchestrator asking the user for missing facts identified by the sufficiency reviewer), so pill #7 is the correct visual home.
- **`scripts/tests/test_render_live_progress.py` `test_maps_each_canonical_phase_to_some_index`** test list extended to include `"research_sufficiency_followup_pending"`. The 18-phase test enumeration now matches the 18-value `current_phase` enum in `state-schema.md` exactly.

**Part C — Manifest hygiene.**

- v0.7.0 had a manifest-match drift: `.claude-plugin/plugin.json` was at `0.7.0` but `README.md` badge still said `0.6.3`. Fixed in v0.7.1 along with the install-line zip filename. Now all three (plugin.json version, README badge, README install line) match `0.7.1` and the `dist/memoforge-0.7.1.zip` artifact.

### Tests

54 renderer tests pass (was 54 in v0.7.0; +0 new but Phase 6 sub-test enum count is now 18 values vs 17). Smoke-test:
```
python -m unittest scripts.tests.test_render_live_progress -v
```
Full suite (`python -m unittest discover -s scripts/tests`): 137 tests pass.

### Manual cross-check performed for v0.7.1

A defensive cross-check verified that every `current_phase` enum value in `state-schema.md` (18 values) is reachable in `render_live_progress.py`'s `PHASES[].state_phases ∪ TERMINAL_PHASES ∪ REVISION_LOOP_PHASES` set (also 18 values; no missing, no extra). Also verified every `live_progress.*` field the renderer reads (`active_subagents`, `active_subagent` backcompat, `source_counts`, `topic`, `started_at_iso`, `phase_started_at_iso`, `timeline`, `artifact_id`, `html_path`) has at least one writer in the codebase. No other dashboard-data drift detected.

### Effect on users

**Discipline change (Part A):** future production runs should no longer show the "flicker" where the dashboard briefly displays a custom rich layout (with per-researcher DONE/RUNNING badges and case citations) for a few seconds before reverting to the standard renderer output on the next phase transition. Orchestrators following v0.7.1 prose will stay on the renderer-canonical layout consistently. If improvisation is observed in a future run, that is a bug to file against this contract — not new desired behaviour.

**Bug fix (Part B):** when sufficiency reviewer returns `targeted_followup_needed` with `main-session` blocking_gaps and the Phase 6.6 user-followup gate fires, the dashboard now correctly shows pill #7 "Sufficiency" as the current phase (yellow-pulsing), pills #1–#6 as completed, and pills #8–#13 as future. "6 of 13 phases complete" instead of the broken "0 of 13".

### Manifest match

`.claude-plugin/plugin.json (0.7.1) === README badge (0.7.1) === README install line (memoforge-0.7.1.zip) === CHANGELOG top entry (0.7.1) === dist/memoforge-0.7.1.zip`.

## 0.7.0 — 2026-05-26 (cross-run learning + Lessons Studio)

**The plugin now accumulates lessons across memo tasks and exposes them for one-click apply/reject via a new Lessons Studio skill. This is the first release where the pipeline LEARNS from its own production history — what kinds of blocking issues recur, which intake questions historically prevent Phase 6.6 follow-ups, which MCP queries consistently fall through to WebFetch fallback. No content from any specific memo crosses tasks; only structural signals (counts, categories, scores, query patterns) accumulate. All learning artifacts live under `~/.claude/plugin-data/memoforge/` — the plugin install dir is never modified at runtime.**

### Why

After ~30 memo tasks of varied classification it became visible that the pipeline was repeatedly catching the SAME kinds of issues, particularly: (a) memo-writer overconfidence cues like "clearly", "obviously" surfacing as `counterargument-reviewer:overconfidence` blockers, (b) statute-paraphrase patterns triggering `citation-auditor:source_drift` for the same handful of articles (GDPR Art. 6, AI Act Art. 14), (c) Phase 6.6 firing in ~60% of `cross_border` tasks on the same missing-fact category ("EEA controller established?"), (d) LDH MCP returning empty for jurisdiction-CY queries with predictable fallback to canonical Cyprus government portals. The corrections were lossy — each task's mediator/reviewer feedback was discarded after export. The same lessons had to be re-discovered every run.

v0.7.0 captures these patterns structurally without the user retyping rules into prompt files. The architecture follows three principles:

1. **LLM judgment, not pure numeric counting.** Lessons are gated by both (a) a numeric threshold (e.g. ≥3 distinct tasks across ≥2 classification.types) AND (b) an LLM quality gate (coherence, overlap-with-built-in, specificity, false-positive risk). Either gate alone is brittle; both together are robust.

2. **Semantic clustering rescues cross-surface-form patterns.** Strict pattern_key grouping (e.g. `prose:overconfidence:clearly` vs `prose:overconfidence:plainly`) misses semantically-equivalent patterns. After threshold check, the LLM examines near-threshold groups within the same `kind` prefix and merges semantically-similar ones — `clearly`+`plainly`+`obviously` (n=2 each individually) become a single "weasel-words" lesson (n=6 combined).

3. **Plugin install dir is immutable at runtime.** All overrides live under `~/.claude/plugin-data/memoforge/`. Agents conditionally READ overrides; they never WRITE to the plugin install dir. The Lessons Studio is the only writer of override files, and only via explicit user Apply/Reject action.

### What changed

**Part A — Tier-2 structured tool-call telemetry (`skills/memo/references/logging-contract.md`).**

A new Tier-2 logging section documents `<work_dir>/logs/<agent>-tools.jsonl` — structured JSONL files emitted by researchers (statutory, case-law, doctrinal), `currency-checker`, and `citation-auditor` on every external tool call (MCP, WebSearch, WebFetch). Schema per line: `ts, tool, category (mcp|websearch|webfetch), query (≤120 chars), topic_key, result (ok|empty|error|ratelimited|timeout), latency_ms, result_size_hint, selected_url, fallback_used, iteration`. The existing Tier-1 plain-text per-step log (`<agent>.log`) is preserved unchanged — Tier 2 is a separate sibling file targeted at machine consumption (the `lessons-extractor` agent at Phase 11.5). Best-effort; failures swallow silently.

`topic_key` is the join field for cross-task pattern detection. Researchers compute it deterministically per call: statutes → `<jurisdiction>-<instrument-shortname>-<article>` (e.g. `eu-aiact-art-14`); case-law → `<jurisdiction>-<court>-<case-shortname>`; doctrinal → `<topic-keyword-bigram>` or `<regulator-doc-shortcode>`. `currency-checker` and `citation-auditor` mirror the researcher's topic_key to enable end-to-end pipeline correlation per source.

**Part B — `lessons-extractor` agent (NEW, `agents/lessons-extractor.md`).**

Opus-model subagent dispatched once per task at Phase 11.5 (after successful docx export). Two-pass operation:

- **Pass 1 — Signal extraction.** Reads this task's `state.json`, `events.jsonl`, all `reviews/v*-*.json`, drafts/v1 + final, `intake/`, `research/{currency-report,research-sufficiency}.json`, AND all `logs/*-tools.jsonl`. For each candidate, computes a deterministic `pattern_key` and writes a small JSON signal file to `~/.claude/plugin-data/memoforge/signals/<task_id>-<seq>.json`. Caps at 10 signals per task. Skips signals whose pattern_key matches an already-applied override (dedup-at-source).

- **Pass 2 — Cross-task synthesis.** Reads accumulated signals from last 30 days. Groups strictly by `pattern_key`. For groups that cross numeric threshold, the LLM runs semantic clustering for near-threshold neighbors within the same `kind` prefix (`n ≥ threshold-2 AND n < threshold`; max 1 merge per kind per round; bias toward NOT merging). Then quality gate (coherence / overlap-with-built-in / specificity / false-positive-risk checks). Survivors promote per tier:
  - **Tier 1** (intake hints, currency hints, MCP health) → auto-applied to a section of `learned-patterns.md` with an audit record at `lessons/applied/auto/<lesson_id>.md` (so the Studio can show + Undo it).
  - **Tier 2/3** → written as pending lessons under `lessons/pending/<lesson_id>.md` for Studio review.
  - **Tier 0** (aggregate stats: convergence, reviewer trajectories, MCP latencies) is NOT routed through the promotion path. It's recomputed unconditionally in a separate §"Always-recompute Tier 0 sections" step every Pass 2 — no lesson_id, no audit record per refresh. The `Last update: <ISO>` line at the top of `learned-patterns.md` is the only audit signal for Tier 0 refreshes.

Returns a structured summary parsed by `memo` skill: `signals_written`, `lessons_promoted` (Tier 1+2+3, NOT including Tier 0 recomputes), `auto_applied_count` (Tier 1 only), `pending_count` (Tier 2+3), plus judgment counters `groups_examined`, `clustering_merges`, `quality_gate_vetoed`.

**Part C — Phase 11.5 in `memo` skill (`skills/memo/SKILL.md`).**

New phase between docx visibility step and Phase 12 summary. Dispatches `lessons-extractor` best-effort; failures never block the task. Emits `agent_dispatched`/`agent_returned`/`lessons_extracted` events (Tier-2 event documented in `events-contract.md`). `active_subagents` plumbing applied in full — a `🛠 lessons-extractor` chip surfaces under the in-progress Summary pill (#13) for the 5-30 seconds the extractor runs, then is cleared via an explicit post-return render (Phase 11.5 is the LAST dispatch of the run, so the standard "next phase_transition refreshes the dashboard" assumption doesn't apply — explicit render needed). One mantra deliberately skipped: TodoWrite update (preserves the canonical 14-item list invariant; the lessons system has its own audit/UI surfaces — events.jsonl, the Studio dashboard, the Phase 12 chat hint). Exceptions documented inline.

If `lessons_extracted.data.pending_count > 0`, Phase 12 appends ONE line to the delivery summary: `💡 N new lessons proposed for review. Run /memoforge:lessons.` Silent otherwise.

**Part D — Phase 1.4 advisory read in `memo` skill (`skills/memo/SKILL.md`).**

Before Phase 2a intake, the orchestrator reads `~/.claude/plugin-data/memoforge/learned-patterns.md` once (if present, fresh — <30 days). One actioned downstream use point in v0.7.0: reorder intake questions in Phase 2a based on `§ Intake-question priority hints` matching question-header substrings. Classification-keyed hints (e.g. `compliance_check → "processing volume"`) are matched by their question subject only — `state.json.classification.type` is set at Phase 3 (planning) and unavailable at Phase 2a, so the classification prefix is ignored at hint-application time. The Phase 1.5 mode-pick stat hint envisioned in the design was DROPPED for v0.7.0 because classification.type is similarly unavailable at Phase 1.5; defer to a future Phase 3-aware variant.

Researchers are NOT informed from here — they read their own `agent-overrides/<name>.md` files independently at dispatch. Passive read, no state transition, no event emission. Other sections of `learned-patterns.md` (§ Currency hints, § MCP health, § Recurring patterns) are accessible for human inspection via the Lessons Studio's "View full learned-patterns.md" command but are not actioned by the orchestrator.

**Part E — Lessons Studio skill (NEW, `skills/lessons/SKILL.md`).**

User-facing UI invoked via `/memoforge:lessons`. Reads/writes plugin-data only. Compact summary screen (≤25 lines) groups pending lessons by `target_file`, surfaces auto-applied-since-last-visit count. Top-level menu options (AskUserQuestion-based, plain-text fallback): Review one-by-one, Apply all pending, Show auto-applied, Show recently rejected, Exit. Per-lesson decisions: Apply / Reject (30-day cooldown) / Defer / Edit-before-applying. Apply appends the proposed change as a dated H3 section to the target override file with backlink audit comment, moves lesson to `applied/manual/`. Reject moves to `rejected/` with cooldown. Rollback subcommand (`/memoforge:lessons rollback <lesson_id>`) removes the H3 section from the override file and moves the audit record to `rejected/`.

**Part F — Override file infrastructure (`~/.claude/plugin-data/memoforge/`).**

Two override types:
- `prose-style-overrides.md` — appends to built-in `lib/prose-style.md` (read by `memo-writer` and indirectly by `revision-mediator` via its prose-style reads).
- `agent-overrides/<agent>.md` — augments a specific agent's prompt (read by `memo-writer`, `fact-assumption-analyst`, `citation-auditor`, `statutory-researcher`, `case-law-researcher`, `doctrinal-researcher`).

Each of those 6 agents got an `## Optional override (v0.7.0+)` section near the top of its prompt with conditional Read instruction, priority order, and explicit "skip silently if missing/empty/malformed" behavior. Built-in plugin behavior remains authoritative; overrides are advisory and additive.

**Part G — Plugin-data layout.**

```
~/.claude/plugin-data/memoforge/
├── profiles/                              (existing — Style Studio, unchanged)
├── learned-patterns.md                    (NEW; auto-managed advisory)
├── prose-style-overrides.md               (NEW; Studio-managed)
├── agent-overrides/                       (NEW)
│   ├── memo-writer.md
│   ├── fact-assumption-analyst.md
│   ├── citation-auditor.md
│   ├── statutory-researcher.md
│   ├── case-law-researcher.md
│   └── doctrinal-researcher.md
├── signals/                               (NEW — accumulation layer)
│   ├── <task_id>-<seq>.json
│   └── archive/<YYYY-MM>/                 (future: monthly rollover, Phase 3 polish)
└── lessons/
    ├── pending/<lesson_id>.md
    ├── applied/auto/<lesson_id>.md
    ├── applied/manual/<lesson_id>.md
    ├── rejected/<lesson_id>.md
    └── meta/{last_review,stats,pattern_keys,clustering-suggestions}.json
```

Env var override: `MEMOFORGE_LESSONS_HOME` (mirrors `MEMOFORGE_PROFILES_HOME` from Style Studio).

**Part H — Phase 12.5 workdir tidy (`skills/memo/SKILL.md`).**

After Phase 12 delivery summary and Final TodoWrite update, before end-turn, the orchestrator does a best-effort cleanup pass on the task `work_dir` top level. Removes intermediate / stray files that don't belong at top level: all `live-progress*.html` rendered snapshots (master + per-subagent / per-reviewer / per-phase variants — their data is preserved in `state.json.live_progress.timeline` and `events.jsonl phase_transition` events; the Cowork artifact card stays renderable because it's content-addressed on Cowork's side), all top-level `*.py` stray scripts (canonical Python scripts live at `${CLAUDE_PLUGIN_ROOT}/scripts/`, never in work_dir — `lp_done_render.py`/`lp_run.py` and similar are bug artifacts from buggy subagent live-progress emissions), and all `*.tmp` atomic-write leftovers anywhere in work_dir.

After tidy, the top-level work_dir contains ONLY the deliverable (`memo-<slug>.docx` + `.md` mirror), schema-referenced infra files (`state.json`, `events.jsonl`), user-facing planning/revision artifacts (`plan.md`, `changelog.md`), and the canonical subdirectories (`intake/`, `research/`, `drafts/`, `reviews/`, `logs/`, `widgets/`, `checkpoints/`).

Tidy is **skipped** on failure / cancellation / fallback paths (final_status starting with `fallback_`, or current_phase = `failed` / `cancelled_by_user`) — those paths may have unusual artifacts at top level that diagnostics need; better leave the workdir untouched for forensics. All other normal-completion `final_status` values (`approved_on_v<N>`, `forced_exit_on_v<N>_with_remaining_issues`, `manual_review_required_on_v<N>`, `accepted_early_on_v<N>`) trigger tidy.

Best-effort throughout — failures of the `find ... -delete` commands swallow silently via `|| true`. The user already has the docx + audit trail; tidy is purely cosmetic UX polish.

### Verification (end-to-end smoke test)

1. Run a memo task. Check `<work_dir>/logs/*-tools.jsonl` exists with one JSONL line per researcher tool call.
2. Check `<work_dir>/events.jsonl` for a `lessons_extracted` event with `signals_written`, `groups_examined`, `clustering_merges`, `quality_gate_vetoed` counters.
3. Check `~/.claude/plugin-data/memoforge/signals/` for new signal files matching this task_id.
4. Run 5+ tasks of varied classification. Run `/memoforge:lessons summary` — verify pending count and auto-applied stats render.
5. Run `/memoforge:lessons`, Apply a pending lesson — verify target override file gets the new H3 section AND lesson moved to `applied/manual/`.
6. Run a fresh memo — verify the relevant agent reads its override at start (look for the Read tool call in `<work_dir>/logs/<agent>.log`).
7. `/memoforge:lessons rollback <lesson_id>` — verify section removed from override and audit record moved to `rejected/`.

### Files changed in this release

- NEW `agents/lessons-extractor.md` (~444 lines, opus model, two-pass with semantic clustering + quality gate)
- NEW `skills/lessons/SKILL.md` (~470 lines, interactive Studio with review/apply/reject/defer/rollback)
- EDIT `agents/memo-writer.md` (+~25 lines: dual override read at top — prose-style-overrides.md AND agent-overrides/memo-writer.md)
- EDIT `agents/fact-assumption-analyst.md` (+~20 lines: optional override read)
- EDIT `agents/statutory-researcher.md` (+~50 lines: Tier-2 telemetry block + optional override read)
- EDIT `agents/case-law-researcher.md` (+~50 lines: same as statutory)
- EDIT `agents/doctrinal-researcher.md` (+~50 lines: same)
- EDIT `agents/currency-checker.md` (+~25 lines: Tier-2 telemetry only — no override read; this agent is mechanical-verification, not learning-driven)
- EDIT `agents/citation-auditor.md` (+~50 lines: Tier-2 telemetry + optional override read)
- EDIT `skills/memo/SKILL.md` (+~160 lines: Phase 1.4 advisory read + Phase 11.5 lessons-extraction dispatch + Phase 12 conditional hint)
- EDIT `skills/memo/references/logging-contract.md` (+~85 lines: Tier-2 structured tool-call telemetry section)
- EDIT `skills/memo/references/events-contract.md` (+~50 lines: `lessons_extracted` event documented as Tier-2 with judgment-counter fields)
- BUMP `.claude-plugin/plugin.json` to 0.7.0 with updated description

### What this release does NOT do (out of scope)

- **No edits to the plugin install dir at runtime.** Agent definitions under `${CLAUDE_PLUGIN_ROOT}/agents/*.md`, `lib/prose-style.md`, and `templates/*.md` are immutable at runtime. Lessons flow into per-user override files under plugin-data, never into the plugin codebase.
- **No automatic merging of accepted lessons upstream into the plugin.** Users can manually upstream a recurring lesson into the canonical plugin via PR if they want; the Studio does not do this automatically.
- **No LLM auto-grading of lessons.** The user remains the gate for Tier 2/3 lessons via the Studio's Apply/Reject decisions. The lessons-extractor's quality gate filters out obviously-bad candidates but the user reviews surviving proposals.
- **No cross-machine sync of plugin-data.** Each plugin install's `~/.claude/plugin-data/memoforge/` is local. Users who want to share patterns can manually copy override files across machines.
- **No monthly archive rollover for old signals.** Deferred to a future patch; the `signals/archive/` directory is created but currently unused. Signal files accumulate; the 30-day threshold window means signals older than 30 days are excluded from threshold counts but remain on disk. (Shipped in v0.8.0 — see v0.8.0 §"Part C — Monthly archive rollover".)
- **No visualize widget for the Studio summary.** v0.7.0 ships text-only Studio UI; visualize widget is Phase 3 polish. (Shipped in v0.8.0 — see v0.8.0 §"Part A — Visualize widget for the Lessons Studio summary".)

### Reference

Plan and design rationale: see the in-conversation plan (architectural background on the two-stage signals→lessons model, threshold rationale, semantic-clustering conservatism rules, privacy contract).

---

## 0.6.3 — 2026-05-26 (visualize hook pre-approval + Phase 6.6 user-followup gate)

**Two improvements based on the v0.5.4-v0.5.7 hook lesson (plugin-bundled `PreToolUse` hooks DO work in production Cowork) and the last production run's `targeted_followup_needed` outcome (researchers were re-dispatched on a gap the user could have answered in seconds, but the user was never asked).**

### Why

1. **Hook scope extension:** v0.5.7's `hooks/hooks.json` pre-approves only the three `mcp__cowork__*` artifact tools. The visualize widget tools (`show_widget`, `read_me`) get called many times per run — Phase 1.5 mode mockup, Phase 2a intake elicitation, Phase 3 plan diagram, Phase 12 final dashboard, 5 inline milestone trackers, plus the new Phase 6.6 elicitation widget added in this release. Each call hits the same #24433 mechanism that originally drove the cowork-artifact prompt storm: Cowork's "Always allow" UI does not persist across subagent dispatch boundaries. Pre-approving these via the existing hook is a one-line regex change that costs nothing and eliminates the next batch of subagent-boundary prompts.

2. **Phase 6.6 user-followup gate:** `agents/research-sufficiency-reviewer.md`'s JSON schema defined `blocking_gaps[].target_agent` as a 4-value enum including `"main-session"` — a signal that "this gap can only be closed by asking the user". But `skills/memo/SKILL.md:981-985` never read `target_agent`; on `targeted_followup_needed` it sent every gap's `recommended_followup_prompt` to researchers, including gaps that no researcher could answer (missing user facts like controller-establishment country, processing volume, opt-in vs default-on). The user reported this verbatim after a production run: *"иногда после ресерча может быть такая ситуация что у нас попросить могут доп вопросы? targeted_followup_needed — вот что выдало в последний прогон. Но этого у нас не продумано, ничего не спрашивают у пользователя дополнительно."* Phase 6.6 fixes the gap structurally: when sufficiency returns `targeted_followup_needed` AND has `main-session` blocking_gaps, the orchestrator ends the turn with a visualize elicitation widget (or text fallback) asking those exact follow-up questions. User answers, orchestrator writes them to `intake/user-facts.md`, optionally re-dispatches researchers for the remaining researcher-side gaps, and re-runs sufficiency once. Bounded by the existing `attempts.research_followup` budget (one user-followup OR one researcher-followup per task, not both).

### What changed

**Part A — Visualize hook pre-approval.**
- **`hooks/hooks.json` extended with a SECOND matcher block** for `mcp__.*visualize.*__(show_widget|read_me)`. Tight regex (requires `visualize` substring inside the namespace) so an arbitrary user MCP exposing `show_widget` won't be auto-approved unless it self-identifies as a visualize variant. Covers both plugin-scoped (`mcp__plugin_visualize_*__show_widget`) and Cowork UUID-scoped (`mcp__<uuid-with-visualize-tag>__show_widget`) namespaces. The existing cowork matcher is unchanged. Each entry uses the same inline `python3 -c` invocation pattern from v0.5.7 (no env-var dependency).
- **`README.md` gains two new fallback blocks** alongside the existing cowork-artifact fallback (line 36): one for visualize tools (in case the hook regex doesn't match a specific Cowork UUID variant) and one for the bundled MCP servers (LDH + CourtListener — these are NOT pre-approved by hook because their function names overlap with potential other MCPs and Cowork's UUID-scoped namespaces would require a wildcard regex with unintended-auto-approval risk).
- LDH/CourtListener tools are intentionally NOT added to `hooks.json` — fallback is README-documented user settings.json edits only.

**Part B — Phase 6.6 user-followup gate.**
- **`agents/research-sufficiency-reviewer.md` JSON schema extended:** `blocking_gaps[]` entries with `target_agent: "main-session"` MUST now include a non-null `followup_question` block (question text + ≤12-char header + 2-4 options + `default_assumption_if_skipped` + `rationale_md` — same shape as `fact-assumption-analyst`'s intake questions). New section "## Generating followup_question for main-session gaps" explains the authoring rules (bucketed options for open-ended facts, binary options for yes/no, free-text fallback via the widget's `<n>:custom text` syntax).
- **`skills/memo/SKILL.md` Phase 6 rewritten with four branches (B6a-B6d):** the orchestrator partitions `blocking_gaps[]` by `target_agent` into Subset R (researcher gaps, existing behavior) and Subset U (main-session gaps, new). Branch B6a fires the Phase 6.6 gate when Subset U is non-empty AND `attempts.research_followup == 0`; it transitions `current_phase = "research_sufficiency_followup_pending"`, populates `state.json.sufficiency_followup.{questions, subset_r, status}`, renders the elicitation widget (Path A) or text fallback (Path B), emits `gate_announced`, ends the turn. Branches B6b-B6d preserve all pre-v0.6.3 behavior.
- **`skills/memo/SKILL.md` Phase 5 heads-up updated** to pre-warn the user about the new conditional gate so they know what to expect when it fires.
- **`skills/continue/SKILL.md` new `research_sufficiency_followup_pending` handler** with three sub-paths: explicit `followup: 1A 2C 3:my custom text` parsing (mirrors Phase 2b Parser 1), `proceed`-on-defaults, `cancel`. On user reply, parses answers, appends to `intake/user-facts.md` under `## Follow-up answers (after sufficiency review)`, writes `research/followup-response.md`, atomically updates state, then re-dispatches researchers for `subset_r` (if non-empty) followed by `research-sufficiency-reviewer`. Emits `gate_answered` per events-contract.md.
- **`skills/memo/state-schema.md` adds the `research_sufficiency_followup_pending` phase enum value** and a new top-level `sufficiency_followup` object documenting the question/answer/budget shape. `attempts.research_followup` description updated to note that the budget now covers both researcher AND user follow-ups (max 1 total per task).
- **`skills/memo/references/widget-schemas.md` new §"Sufficiency follow-up" section** specifying the data payload (reuses §Elicitation's HTML layout verbatim — same widget code, different data source). Snapshot path `$WORK_DIR/widgets/phase66-followup-elicitation.html`. Event payload `{"phase": "6.6-followup", "module": "elicitation", "question_count": <N>}`.
- **`skills/memo/references/events-contract.md` registers the new `gate_name: "sufficiency-followup"`** under the existing `gate_announced` / `gate_answered` taxonomy. No new event type — existing taxonomy covers it.
- **`skills/memo/references/always-deliver.md` adds two Phase 6 fallback rows** for (a) reviewer-output schema violation (Subset U entry with `followup_question == null` → fall through to Branch B6b), and (b) Subset U gaps remaining unresolved after the user follow-up (promote to `drafting_warnings[]`).

### Effect on users

**Permission-prompt-side (Part A):** zero new permission prompts for visualize widgets during a memo run. Users who had been seeing repeated `show_widget` prompts at Phase 1.5 / 2a / 3 / 12 now see none.

**Pipeline-flow-side (Part B):** when the sufficiency reviewer surfaces a fact-gap that only the user can answer (e.g. *"Is the data subject in the EEA or outside?"* or *"Approximately how many monthly active users does the feature touch?"*), the user is now asked directly via a single follow-up widget BEFORE drafting — instead of the pipeline pretending researchers can resolve a fact gap they can't. Wallclock impact: one extra end-turn per task IF the gate fires (most tasks don't trigger Subset U gaps when intake is thorough). Quality impact: significantly better draft when intake misses a material fact, because the gap is resolved with the user's real answer rather than buried in `drafting_warnings`.

**Backward compatibility:** legacy tasks created on v0.6.2 or earlier resume cleanly. The new `sufficiency_followup` state.json field defaults to `null` (treated as "no gate fired"); the new phase enum value `research_sufficiency_followup_pending` doesn't appear in any pre-v0.6.3 state.json. Continue skill handles both the new explicit `followup:` and `proceed` parsers AND the legacy `answer:` / `cancel` parsers without ambiguity (different parser paths run in different `current_phase` branches).

### Tests

131 existing tests still pass (no Python script changes). Hook regex validated manually against 10 sample tool names:
```
python3 -c "import re; ..."  # all 10 cases match the expected matcher (cowork / visualize / neither)
```

Smoke-test for the inline visualize hook command:
```
python3 -c "import json,sys; sys.stdout.write(json.dumps({'hookSpecificOutput':{'hookEventName':'PreToolUse','permissionDecision':'allow','permissionDecisionReason':'memoforge visualize widgets pre-approved (Phase 1.5 mockup / Phase 2a + 6.6 elicitation / Phase 3 plan diagram / Phase 12 final dashboard / milestone trackers)'}}))"
```
Returns valid JSON containing `permissionDecision: allow` — confirmed in build.

### Manifest match

`.claude-plugin/plugin.json === README badge === dist/memoforge-0.6.3.zip`.

## 0.6.2 — 2026-05-26 (topic header + per-subagent chips + transitions audit)

**Three dashboard refinements based on v0.6.1 production observations.** User feedback: the header line truncated the raw query awkwardly mid-sentence ("We're a US-based SaaS company planning to launch a new feature that uses AI to analyze customer support chat transcripts (from EU users) …"), and parallel researcher dispatches collapsed into a single uninformative chip ("🛠 3 researchers (parallel)") instead of showing each subagent name.

### What changed

- **NEW `state.json.live_progress.topic` field** — short 3–7 word theme generated by the orchestrator at Step 1d (mint) from `user_query`. Replaces the truncated raw-query header in the dashboard. Examples: `"GDPR compliance for AI support feature"`, `"DPA-vs-clickwrap dispute analysis"`. When null/empty, renderer falls back to the old truncation behavior (≤137 chars + "…"). The SKILL.md Step 1d instructions include three good-vs-bad topic examples to anchor the orchestrator's generation.

- **`live_progress.active_subagent` (string) → `live_progress.active_subagents` (list)** — schema change so parallel dispatches surface ONE chip PER subagent. Phase 5 parallel research now shows `🛠 statutory-researcher · 🛠 case-law-researcher · 🛠 doctrinal-researcher` side-by-side instead of the v0.6.0–v0.6.1 collapsed `🛠 3 researchers (parallel)` label. Phase 9 parallel reviewers similarly show one chip per reviewer.
  - SKILL.md mantra updated with explicit examples for both single (`["memo-writer"]`) and parallel (`["statutory-researcher", "case-law-researcher", "doctrinal-researcher"]`) dispatches.
  - Backwards-compat: renderer still accepts the legacy bare-string `active_subagent` field and treats it as a single-element list — no breakage for in-flight tasks that started on 0.6.0–0.6.1.

- **Transitions audit** — verified that every phase transition in the pipeline either (a) immediately dispatches a subagent which emits a live-progress `start` update (subagent emissions flush real-time in the chat scroll), or (b) is a user gate where the user-input event itself provides the visible signal. The only exceptions are Phase 10→11 (docx export, single Bash command) and Phase 11→12 (final orchestrator summary) — both happen at end-of-pipeline where chat naturally flushes. No additional emission points needed. The "MANDATORY downstream responsibility at every phase transition" SKILL.md block remains the canonical orchestrator-side discipline; subagent-side emissions (per v0.5.1 Pre-return checklist hardening) provide the real-time flush.

### Tests

54 renderer tests pass (was 48 in v0.6.1; +6 new for topic + active_subagents list). All 131 baseline pass. Smoke-test commands:

```
python -m unittest scripts.tests.test_render_live_progress -v
python -m unittest discover -s scripts/tests
```

### Effect on users

Next memo run on 0.6.2 shows a clean topic line in the header (e.g. `GDPR compliance for AI support feature`) instead of the awkwardly-truncated query. During Phase 5 parallel research, the user sees three distinct chips refreshing in real time: `🛠 statutory-researcher`, `🛠 case-law-researcher`, `🛠 doctrinal-researcher`. Same for Phase 9 reviewers (Full mode = 5 chips).

### Manifest match

`.claude-plugin/plugin.json === README badge === dist/memoforge-0.6.2.zip`.

## 0.6.1 — 2026-05-26 (fix phase numbering + execution order in dashboard)

**Fixes two layout defects the user flagged after the v0.6.0 install.** Both stem from legacy phase IDs in `scripts/render_live_progress.py`'s `PHASES` array.

### Why

User flagged the dashboard phase pills as confusing: *"А почему стадия 1.5 идёт после 2? и вообще почему есть стадия 2a, но нет просто 2? Есть много нелогичного тут, это путает."* Two real defects:

1. **Wrong execution order in the pill row.** `PHASES` placed `Mode (1.5)` at index 1 and `Intake (2a)` at index 2 — but the actual pipeline runs Init → Intake → Mode, so the pill layout did not reflect runtime reality. When the orchestrator was at `mode_pick_pending`, the dashboard would mark Mode as "current" but render Intake as "future" (despite the user having already answered intake questions).
2. **Legacy non-sequential IDs** (`1.5`, `2a`) inherited from an earlier pipeline design. The "1.5" placeholder existed for a planned Phase-1 sub-step that never landed; "2a" suggested a non-existent "2b". Users naturally expected clean 1–13.

### What changed

- **`scripts/render_live_progress.py` `PHASES` array** rewritten with sequential 1–13 IDs and the actual execution order:

| Pos | Was (v0.6.0) | Now (v0.6.1) |
|---|---|---|
| 0 | 1 Init | 1 Init |
| 1 | 1.5 Mode | 2 Intake |
| 2 | 2a Intake | 3 Mode |
| 3 | 3 Classify | 4 Plan |
| 4 | 4 Approve | 5 Approve |
| 5 | 5 Research | 6 Research |
| 6 | 6 Sufficiency | 7 Sufficiency |
| 7 | 7 Source-pack | 8 Source-pack |
| 8 | 8 Draft v1 | 9 Draft v1 |
| 9 | 9 Revise | 10 Revise |
| 10 | 10 Polish | 11 Polish |
| 11 | 11 Export | 12 Export |
| 12 | 12 Summary | 13 Summary |

- `Classify` label renamed to `Plan` (the state_phase is `planning`; "Plan" matches the user's mental model better than the more technical "Classify").
- **Mode is now rendered AFTER Intake** — matching actual orchestrator behavior (intake elicitation happens first; mode pick uses intake answers as context).
- **No state schema change.** `state.json.current_phase` enum is unchanged (still uses `intake_questions_pending`, `mode_pick_pending`, etc.). Only the display-side `PHASES` mapping changed.
- **No agent prompt changes.** Agents reference state phases by name, not by display ID.

### Tests

All 131 baseline tests pass — none referenced specific display IDs (counts like "5 of 13 phases" stay correct because Research is still at index 5 in both orderings).

### Effect on users

Next memo run on 0.6.1 shows pills in execution order: `1 Init → 2 Intake → 3 Mode → 4 Plan → 5 Approve → 6 Research → ...`. When the orchestrator is at `mode_pick_pending`, the dashboard correctly marks Init AND Intake as completed (they really are), Mode as current, and the rest as future. No more "Mode at position 2 but Intake at position 3" confusion.

### Known follow-up

`skills/memo/references/progress-tracker.md` (the separate 5-render milestone widget) still uses the legacy 1.5 / 2a / 3 IDs in its data payload schema. That widget renders only 5 times per run and is in a different visual channel (inline visualize widget vs sidebar artifact card); inconsistency between the two surfaces is a minor cosmetic issue. If user reports the milestone widget IDs as confusing too, v0.6.2 will harmonise.

## 0.6.0 — 2026-05-26 (dashboard polish + denser updates + real-time JS tickers)

**The live-progress dashboard gets a flat-design refresh, three new context chips, real-time ticking timers, and ~50 % more update_artifact calls per Full-mode run.** v0.5.x established that subagent-side artifact streaming works end-to-end through Cowork (hook bypass, mint placement, all 15 agents instrumented). v0.6.0 makes the resulting dashboard pleasant to read and visibly alive during the long autonomous blocks.

### Why

User feedback after v0.5.7 production run (2026-05-26): "некрасивый трекинг и не информативный … хотелось бы чтобы таймер прямо в режиме реального времени тикал … и побольше этих апдейтов расставить по пайплайну, чтобы они обновлялись часто и прогресс был виден хорошо." Three concrete asks: flat-design visual polish, real-time ticking timer, more update_artifact emissions throughout the pipeline. Plus three additional info items the user picked in the clarification round: source counts after research, active subagent name + step, iteration counter for revision loop.

### What changed

- **`scripts/render_live_progress.py` rewritten with flat-design HTML + inline JS tickers.**
  - **Hero current-step block** is now the visual headline: large 19 px font for the current activity, a pulsing dot, eyebrow showing `Phase 5 · Research · Research`, big elapsed-in-phase and total counters that tick every second via JS.
  - **Compact 13-phase pill row** below the hero — secondary visual, smaller than v0.5.x.
  - **Three info chips** (only render when their data is present):
    - `📊 23 statutes · 14 cases · 8 doctrine` — from `state.json.live_progress.source_counts` (populated by source-pack-builder).
    - `🛠 case-law-researcher` — from `state.json.live_progress.active_subagent` (set by orchestrator at each Task dispatch).
    - `🔁 iteration 2 of 3` — from `state.json.current_iteration` and `config.max_iterations` during the revision loop.
  - **Footer** with `Updated Xs ago` ticker + pulsing alive dot.
  - **Inline `<script>` block** (≤30 lines) reads `data-*` attributes and uses `setInterval(tick, 1000)` to update three timer spans. No `fetch`, no `postMessage`, no harness callback — pure local DOM mutation. Wrapped in try/catch so a sandbox that blocks `<script>` reverts the dashboard to the v0.5.x baseline (tickers frozen between renders) without any other breakage.
  - **Flat-design discipline:** no `box-shadow`, no `gradient`. Soft borders only at section breaks. Verified by unit tests.
- **`scripts/tests/test_render_live_progress.py` extended to 48 tests** (was 32 in v0.5.x). New tests cover: JS block presence, data-attributes, source-counts chip rendering + omission, active-subagent chip rendering + omission, iteration chip during/outside revision loop, hero-terminal class, alive-dot in footer, flat-design discipline (no box-shadow, no gradient).
- **`skills/memo/state-schema.md` adds two fields** under `live_progress`:
  - `active_subagent: null | "<subagent-name>"` (orchestrator-owned).
  - `source_counts: null | {statutes: <int>, cases: <int>, doctrine: <int>}` (source-pack-builder-owned).
- **`skills/memo/SKILL.md` adds MANDATORY orchestrator plumbing** for `active_subagent`: set before every `Task(subagent_type=...)` dispatch, clear (set to null) after subagent returns. Documented as peer of the existing TodoWrite + mark_chapter mantras. Parallel batches use a coarse label like `"3 researchers (parallel)"`.
- **`agents/memo-writer.md` extends the Live progress table with 5 per-section emissions:** `section-exec-summary`, `section-background`, `section-facts`, `section-conclusion`, `section-sources`. Per-issue emissions remain unchanged. Roughly +5–6 strips per draft.
- **`agents/revision-mediator.md` extends the Live progress table with per-reviewer-consumed emissions:** one update per reviewer JSON read between `start` and `done`. 3–5 additional strips per iteration. Sample full sequence: `mediator-iter2-start → mediator-iter2-logic → mediator-iter2-clarity → mediator-iter2-style → mediator-iter2-citations → mediator-iter2-counterarguments → mediator-iter2-done`.
- **`agents/source-pack-builder.md` adds a MANDATORY state-write step:** atomic-Edit `state.json.live_progress.source_counts` with the statutes/cases/doctrine counts before emitting `source-pack-done`. Powers the 📊 chip in the dashboard.
- **`skills/memo/references/live-progress-contract.md` updated** with the new schema fields, the new emission patterns, and the real-time JS ticker section.

### Budget impact

| Mode | v0.5.7 calls | v0.6.0 calls | Delta |
|---|---|---|---|
| Brief (1 iteration, 3 issues) | ~36 | ~45 | +25 % |
| Standard Full (2 iterations, 3 issues) | ~50 | ~75 | +50 % |
| Full (5 iterations, 5 issues) | ~70 | ~110 | +57 % |

Aggressive option (researcher per-source) was rejected in the clarification round — would have flooded chat scroll with 30+ strips per researcher on multi-jurisdictional Full memos.

### Effect on users

- **Same memo output, same wallclock.** Substantive pipeline behavior unchanged.
- **Dashboard visibly alive between update_artifact calls** — the JS tickers update elapsed time every second so the user sees the timer advance even during long quiet subagent runs.
- **Three new context chips** clarify "what's happening" beyond the bare phase label: how many sources research found, which subagent is currently running, which revision iteration is in progress.
- **Denser update_artifact emissions** mean shorter silent gaps between sidebar refreshes during the longest blocks (memo-writer drafting, mediator consolidation).
- The flat-design refresh is purely visual — no functional changes to the chips' meaning or the phase model.

### Verification

- `python -m unittest discover -s scripts/tests` — **all 131 tests pass** (115 baseline + 16 new v0.6.0 tests).
- Manifest match: `.claude-plugin/plugin.json === README badge === dist/memoforge-0.6.0.zip === git tag v0.6.0`.

### Known follow-up if JS sandbox blocks `<script>`

If the Cowork iframe sandbox blocks `<script>` execution (visualize widget spec forbids harness callbacks; cowork artifact iframe may or may not inherit that policy — empirically TBD on first 0.6.0 production run):
- JS tickers stop updating between `update_artifact` calls (same behavior as v0.5.x — no regression, just no improvement on the "alive" feel).
- All other improvements (flat design, chips, more update_artifact calls, source-counts chip, active-subagent chip, iteration chip) still work — they don't depend on JS.
- A v0.6.1 hotfix would replace the JS ticker with a CSS-only "alive" pulse animation that doesn't show actual time but conveys liveness.

## 0.5.7 — 2026-05-26 (inline-Python hook, drops env-var dependency)

**`${CLAUDE_PLUGIN_ROOT}` is NOT expanded in Cowork's hook executor.** v0.5.4–v0.5.6 shipped `hooks/hooks.json` with the docs-recommended form `python3 "${CLAUDE_PLUGIN_ROOT}"/hooks/auto_approve_cowork.py`. v0.5.6 production run (2026-05-26) hit this error verbatim:

```
PreToolUse:mcp__cowork__create_artifact hook error: python3: can't open file 
'C:\Users\User\AppData\Roaming\Claude\local-agent-mode-sessions\.../outputs\${CLAUDE_PLUGIN_ROOT}\hooks\auto_approve_cowork.py'
```

The literal string `${CLAUDE_PLUGIN_ROOT}` was passed to python3 as a path component — Cowork's hook shell did NOT do shell-style variable expansion. This is likely a Windows-specific issue (cmd uses `%VAR%` syntax, not `${VAR}`) but reproduces on the user's local-agent-mode-sessions runtime regardless of the documented bash-style example in the plugins-reference docs.

### What changed

- **`hooks/hooks.json` rewritten with an INLINE `python3 -c` command.** No external script file, no env var dependency. The matcher regex (`mcp__cowork__(create_artifact|update_artifact|list_artifacts)`) restricts the hook to the three specific tools, so the inline Python can unconditionally output the allow JSON without re-checking the tool name. New command:

  ```
  python3 -c "import json,sys; sys.stdout.write(json.dumps({'hookSpecificOutput':{'hookEventName':'PreToolUse','permissionDecision':'allow','permissionDecisionReason':'memoforge live-progress dashboard pre-approved'}}))"
  ```

- **DELETED `hooks/auto_approve_cowork.py`.** No longer needed — the inline Python replaces it.

- **No changes to other plugin behavior.** The v0.5.6 Step 1 mint structure remains intact (which DID work — the orchestrator did call `create_artifact` per the screenshot; the hook is what blocked it).

### Why this should work where v0.5.4–0.5.6 didn't

The inline `python3 -c "..."` command has zero environment-variable dependencies. As long as `python3` is on PATH (which it must be for the rest of the plugin — scripts/render_live_progress.py, scripts/resolve_style_profile.py, etc. — to work), the command executes successfully and outputs the allow JSON. No `${CLAUDE_PLUGIN_ROOT}` to fail to expand; no script file to fail to locate.

### Manual fallback unchanged

The README's `~/.claude/settings.json` `permissions.allow` fallback remains documented for users on Cowork builds where even the inline hook does not work (per docs: "Hook decisions do not bypass deny and ask rules"). If installing 0.5.7 still produces per-call permission prompts, add the three `mcp__cowork__*` allow rules to your user settings.

### Verification

- Inline command smoke-test: `python3 -c "..."` returns valid JSON containing `permissionDecision: allow`.
- `python -m unittest discover -s scripts/tests` — all 115 tests still pass.
- Manifest match: `.claude-plugin/plugin.json === README badge === dist/memoforge-0.5.7.zip`.

## 0.5.6 — 2026-05-26 (move artifact mint into Step 1 / Task setup)

**Structural fix: the mint now lives in Step 1, bundled with the non-skippable Task setup.** v0.5.5 hardened the v0.5.x step 3.5 design with STOP-framing and a 4-pre verification block, but the user pointed out the root structural problem: step 3.5 is a separate optional-feeling step in the middle of Phase 1, easy to mentally check off without executing. Step 1 (state.json init, work_dir resolve, events.jsonl create) is the action orchestrators NEVER skip. Putting the mint there makes it almost impossible to bypass.

### What changed

- **Step 1 (Task setup) gains sub-step 1d "Mint live-progress master artifact"** — six explicit micro-actions:
  1. **1d-1**: probe artifact tool availability via `ToolSearch(query="select:mcp__cowork__create_artifact,mcp__cowork__update_artifact,mcp__cowork__list_artifacts")`.
  2. **1d-2**: atomic-`Edit` `state.json` to populate `live_progress` block + set `config.live_progress_enabled = true`.
  3. **1d-3**: render the initial HTML via `scripts/render_live_progress.py`.
  4. **1d-4**: call `mcp__cowork__create_artifact` (the v0.5.4 hook auto-approves so no prompt).
  5. **1d-5**: append `live_progress_precheck_result` + `live_progress_artifact_minted` events.
  6. **1d-6 (self-verify)**: re-read `state.json` and confirm `live_progress.artifact_id` is non-null; if null, re-execute 1d-2.
- **Old step 3.5 removed.** Its body is gone. A short "moved to Step 1 sub-step 1d" note remains so the orchestrator finds the new location if it follows the old mental model. The "MANDATORY downstream responsibility at every phase transition" block (about ongoing updates at phase changes — NOT the initial mint) is preserved verbatim.
- **Step 4 (dispatch fact-assumption-analyst) verification block updated** — references "Step 1 sub-step 1d" instead of "step 3.5" for the mint-not-done recovery path.
- **Phase 1 step list at the top of the phase** updated to drop the "3.5" entry: now Phase 1 = steps 1, 2, 3, 4 (mint is bundled into step 1).

### Why this fix should work where v0.5.5 didn't

v0.5.5 added STOP-framing and a verification checkpoint, both pointing at step 3.5. But the orchestrator's mental model of "I just need to set up the task before triage" doesn't include step 3.5 — it includes step 1. Putting the mint INSIDE step 1's atomic setup block (alongside state.json init, work_dir resolve, events.jsonl create) means the orchestrator does the mint as part of "setting up the task", not as a separate "live-progress configuration" step that feels optional. This is the same pattern that makes the existing TodoWrite-init reliable (it's part of step 4 dispatch prep, never separated).

### Effect on users

The next `/memoforge:memo` run on 0.5.6 should produce a sidebar "Live artifacts" card with id `memo-<task_id>-live` IMMEDIATELY after the orchestrator completes Task setup — before the MCP precheck, before the visualize precheck, before fact-assumption-analyst dispatch. If the card still doesn't appear, the orchestrator is ignoring even the in-step-1 placement and the next iteration must take a more radical approach (e.g. wrap the mint in `resolve_work_dir.sh` so it's a single deterministic Bash invocation, leaving the orchestrator only the discrete tool call).

### Verification

- `python -m unittest discover -s scripts/tests` — all 115 tests still pass (no scripts changed).
- Manifest match: `.claude-plugin/plugin.json === README badge === dist/memoforge-0.5.6.zip`.

## 0.5.5 — 2026-05-26 (hardens Phase 1 step 3.5 mint against orchestrator skip)

**Hook + permissions work — but orchestrator was skipping the mint itself.** Empirical observation from a v0.5.4 production run: no permission prompts, no errors, no sidebar artifact. Diagnostic via `state.json` inspection: `live_progress_enabled = true` (precheck DID detect tools) but `live_progress = null` (mint call was NEVER made). `events.jsonl` had `mcp_precheck_result` but NO `live_progress_artifact_minted`. The orchestrator detected availability and announced "live-progress artifacts are available" in chat, then skipped the actual `mcp__cowork__create_artifact` call.

### Root cause

Two compounding bugs in v0.5.0–v0.5.4 SKILL.md Phase 1 prose:

1. **Step 4 opening said "After all three preceding steps (Task setup, MCP precheck, Visualize precheck)" — omitting step 3.5.** When step 3.5 was added to the step list at the top of Phase 1, the body of step 4 wasn't updated to reflect the new dependency. The orchestrator, reading step 4 in sequence, sees a 3-dependency requirement and assumes that's complete after MCP+visualize.
2. **Step 3.5 didn't distinguish DETECT from MINT.** The sub-actions ("precheck the tools" vs "actually call create_artifact") were intermingled in the prose. An orchestrator focused on the precheck flow could announce "live-progress is available" and move on, mentally checking off step 3.5 without ever executing the mint tool call.

### What v0.5.5 changes

- **Step 3.5 rewritten with explicit STOP framing and (a)/(b) sub-action structure.** Sub-action (a) is the precheck/detect. Sub-action (b) is "MINT the master artifact (MANDATORY when (a) confirmed availability — DO NOT SKIP)." A warning block at the top of the step calls out the v0.5.0–v0.5.4 observed failure mode by name.
- **Step 3.5 sub-action (b) gains a new sub-step 6 — Self-verify.** The orchestrator reads `state.json` after the mint and confirms `live_progress.artifact_id` is non-null. If null, the orchestrator is instructed to go back and execute step 2 (state.json update) now. Catches the exact failure mode that motivated this patch.
- **Step 4 opening updated to "after all FOUR preceding steps" and gains a 4-pre verification block** — an explicit pre-dispatch checklist that the orchestrator must mentally pass before invoking fact-assumption-analyst. The checklist includes "if `live_progress_enabled = true`, `state.json.live_progress.artifact_id` is non-null AND `events.jsonl` has `live_progress_artifact_minted`." If any checkbox fails, the orchestrator is told to go back and complete step 3.5 first.
- **No agent prompt changes** — only Phase 1 SKILL.md prose. The agent-side Pre-return checklists from v0.5.1 remain intact.

### Why these specific changes

Prior v0.5.1 hardening targeted SUBAGENT done emissions via the Pre-return checklist pattern (which addressed the v0.5.0 failure mode of subagents skipping their final `update_artifact`). v0.5.5 applies the same pattern — strong MANDATORY framing + an explicit pre-action verification block — to the ORCHESTRATOR's Phase 1 step 3.5 mint. The Pre-return checklist worked because it intercepted the LLM at the exact moment it was about to skip. The 4-pre verification block does the same for the orchestrator: it sits between step 3.5 (the optional-feeling precheck+mint) and step 4 (the strongly-felt dispatch), forcing the orchestrator to acknowledge step 3.5's mint outcome before proceeding.

### Effect on users

The next `/memoforge:memo` run on 0.5.5 should produce:
- A sidebar "Live artifacts" card with id `memo-<task_id>-live` visible immediately after the orchestrator completes Phase 1 setup (before fact-assumption-analyst dispatches).
- `state.json.live_progress` populated with `artifact_id`, `html_path`, `started_at_iso`, `phase_started_at_iso`, and a one-entry timeline.
- `events.jsonl` containing `live_progress_precheck_result` and `live_progress_artifact_minted` events.
- Subsequent subagent `update_artifact` calls (already v0.5.1-hardened with Pre-return checklists) flow through the v0.5.4 hook and update the same artifact card in real time.

If the sidebar card STILL doesn't appear after installing 0.5.5: the orchestrator is ignoring the new explicit verification block. Diagnostic: read `state.json` after Phase 1; if `live_progress.artifact_id` is still null, the structural hardening wasn't enough and the next iteration must take a more radical approach (e.g. integrating the mint into a Bash script that the orchestrator MUST execute, leaving only the single tool call as a discrete action).

### Verification

- `python -m unittest discover -s scripts/tests` — all 115 tests still pass (no scripts changed).
- Manifest match: `.claude-plugin/plugin.json === README badge === dist/memoforge-0.5.5.zip`.

## 0.5.4 — 2026-05-25 (re-ships the hook with docs-correct quoting; drops useless settings.json)

**Fixes the underlying root cause of permission prompts.** v0.5.0 saw per-subagent permission prompts. v0.5.2 tried two mechanisms (`settings.json` with `permissions.allow` + PreToolUse hook) — but both were broken: the docs say plugin-bundled `settings.json` only honors the `agent` and `subagentStatusLine` keys (permissions there are silently dropped), AND my hook used wrong env-var quoting in the command field. v0.5.3 removed the broken hook but kept the useless settings.json; predictably the prompts persisted. v0.5.4 fixes both root causes.

### Why my v0.5.2 and v0.5.3 approaches failed

Re-reading the official docs at https://code.claude.com/docs/en/plugins:

> "Plugins can include a `settings.json` file at the plugin root to apply default configuration when the plugin is enabled. **Currently, only the `agent` and `subagentStatusLine` keys are supported.**"

So `{"permissions": {"allow": [...]}}` inside a plugin's `settings.json` is silently ignored. Permissions can only be granted from `~/.claude/settings.json` (user), `.claude/settings.json` (project), `.claude/settings.local.json` (local-project), or managed settings — NOT from a plugin's bundled settings file. v0.5.2's mechanism #1 was a non-mechanism.

For hooks, the docs example at https://code.claude.com/docs/en/plugins-reference uses this quoting:

```json
"command": "\"${CLAUDE_PLUGIN_ROOT}\"/scripts/format-code.sh"
```

The `${CLAUDE_PLUGIN_ROOT}` env var sits in its OWN double-quoted JSON token, with the rest of the path OUTSIDE. v0.5.2 put the variable inside a longer quoted string (`python3 "${CLAUDE_PLUGIN_ROOT}/hooks/auto_approve_cowork.py"`), which prevented Cowork's hook executor from expanding it — hence "no such directory" and the hook crashed instead of auto-approving.

### What 0.5.4 ships

- **NEW `memoforge/hooks/hooks.json`** with the docs-correct quoting: `"python3 \"${CLAUDE_PLUGIN_ROOT}\"/hooks/auto_approve_cowork.py"`. Matcher: `mcp__cowork__(create_artifact|update_artifact|list_artifacts)`.
- **NEW `memoforge/hooks/auto_approve_cowork.py`** — tiny stdlib-only Python script. Reads PreToolUse JSON from stdin, returns `{"hookSpecificOutput": {"permissionDecision": "allow"}}` for the three matching tools, emits nothing for others. Exit code always 0 (the hook never denies). Smoke-tested: matching tool returns allow JSON; non-matching returns empty.
- **DELETED `memoforge/settings.json`** — its `permissions.allow` content was ignored per docs.
- **README** gains a section explaining what the hook does and how to manually add the same allow rules to `~/.claude/settings.json` as a fallback if the hook is not honored by a particular Cowork build.

### Open caveat

Per the official permissions docs, "Hook decisions do not bypass permission rules. Deny and ask rules are evaluated regardless of what a PreToolUse hook returns." If Cowork's host applies a built-in `ask`-style rule to `mcp__cowork__*` tools before plugin hooks fire, this hook still won't suppress the prompts — and the user must use the manual `~/.claude/settings.json` fallback documented in the README. Empirically TBD; user will report after installing 0.5.4.

### Verification

- `python -m unittest discover -s scripts/tests` — all 115 tests still pass.
- Hook smoke test (Git Bash): `echo '{"tool_name":"mcp__cowork__update_artifact"}' | python hooks/auto_approve_cowork.py` returns valid allow-decision JSON; with non-cowork tool returns empty (defer).
- Manifest match: `.claude-plugin/plugin.json === README badge === dist/memoforge-0.5.4.zip`.

## 0.5.3 — 2026-05-25 (hotfix — pulls the broken hook from 0.5.2)

**Removes the broken PreToolUse hook that 0.5.2 shipped.** v0.5.2's `hooks/hooks.json` used `${CLAUDE_PLUGIN_ROOT}/hooks/auto_approve_cowork.py` as the command path, but Cowork's hook execution context does NOT expand `${CLAUDE_PLUGIN_ROOT}` (this env var works in skill-body Bash invocations but is undocumented and not honored in `hooks.json` command fields). Result: the hook's command resolves to a literal path that does not exist on disk, the hook fails to start, and Cowork treats the failure as "block the tool call". v0.5.2 made the prompt situation strictly WORSE than v0.5.1 — instead of repeatedly asking, the tool calls now hard-fail.

### What changed in 0.5.3

- **DELETED** `hooks/hooks.json` and `hooks/auto_approve_cowork.py`. The hook backup is removed entirely.
- **KEPT** `memoforge/settings.json` from 0.5.2 — that file is the declarative permission grant. It does not depend on path expansion and should still suppress per-call prompts when the plugin is enabled.
- No agent or skill prompt changes; the v0.5.1 Pre-return checklist remains intact.

### Why hook-only-no-settings or settings-only-no-hook was the right diagnosis

The "belt-and-suspenders" rationale of v0.5.2 (`settings.json` + hook for defense-in-depth) was sound in principle but my hook implementation depended on an env var that doesn't work in plugin hooks. Re-shipping the hook with the correct path scheme is possible (e.g., resolving via Python's `__file__` so the script knows its own location), but the priority right now is to unblock the user; ship settings-only and revisit hooks only if settings.json proves insufficient empirically.

### Effect on users

- If installing 0.5.3 after 0.5.2: the `hooks/` directory inside the plugin is gone, so the broken hook no longer runs. Cowork artifact tool calls go through the normal permission flow with whatever `settings.json` declares.
- If installing 0.5.3 fresh: same as 0.5.2 minus the hook.
- If `settings.json` alone is enough to suppress permission prompts (which the research said it should be) — user is fully unblocked.
- If `settings.json` alone is NOT enough — user reports back, and v0.5.4 adds a correctly-pathed hook.

### Verification

- `python -m unittest discover -s scripts/tests` — all 115 tests still pass (no scripts changed; hook was outside the test surface).
- Manifest match: `.claude-plugin/plugin.json === README badge === dist/memoforge-0.5.3.zip`.

## 0.5.2 — 2026-05-25

**Pre-grant Cowork artifact tools so live-progress updates do not surface per-call permission prompts.** v0.5.0 production runs showed Cowork prompting the user every time a subagent called `mcp__cowork__update_artifact` — destroying the live-progress UX (15–25+ prompts per memo run). The root cause is host-side: Cowork's "Always allow" toggle does not persist across subagent dispatch boundaries (see GitHub issue [#24433](https://github.com/anthropics/claude-code/issues/24433)). v0.5.2 fixes this with two plugin-bundled mechanisms that both auto-approve the three Cowork artifact tools used by the live-progress dashboard.

### Why

The v0.5.0-probe build used ONE subagent that called `update_artifact` four times in sequence — and Cowork remembered the first approval for the rest. Production v0.5.0 dispatches FIFTEEN different subagents that each call `update_artifact` at their step boundaries, and Cowork's permission scoping resets at each dispatch boundary. Without programmatic pre-grant, the user clicks "Approve" 15–25 times per memo run. Empirically confirmed by the developer on 2026-05-25. Research (see `docs/postmortems/v0.2.0-live-progress.md` and related plan notes) identified two viable programmatic paths; v0.5.2 ships both for defense-in-depth.

### What changed

- **NEW `memoforge/settings.json`** at the plugin root, shipping `permissions.allow` for the three Cowork artifact tools (`mcp__cowork__create_artifact`, `mcp__cowork__update_artifact`, `mcp__cowork__list_artifacts`). Per Anthropic's documented "ship-default-settings-with-your-plugin" pattern, these rules merge into the active session's permission set when the plugin is enabled. Subagents inherit parent-session permissions, so every dispatched subagent picks up the allow rules automatically.
- **NEW `memoforge/hooks/hooks.json`** declaring a `PreToolUse` hook with matcher `mcp__cowork__(create_artifact|update_artifact|list_artifacts)` that invokes the Python script below.
- **NEW `memoforge/hooks/auto_approve_cowork.py`** — a tiny Python hook (no third-party deps). Reads the PreToolUse JSON from stdin, returns `{"hookSpecificOutput": {"permissionDecision": "allow"}}` for the three matching tools, and emits nothing for everything else (defer to normal permission flow). Exit code is always 0 — the hook NEVER denies; it only allows or defers. Tested via `echo '{"tool_name":"mcp__cowork__update_artifact"}' | python hooks/auto_approve_cowork.py` (returns the allow JSON) and same with a non-cowork tool (returns nothing).
- **No agent or skill prompt changes** — substantive pipeline behavior is identical to 0.5.1. The only effect is that Cowork should now stop prompting the user for artifact tool approvals.

### Two mechanisms, defense-in-depth

The settings.json path is the **declarative** mechanism (no code execution; merges allow rules at plugin enable time). The hooks path is the **imperative** mechanism (the hook receives every PreToolUse event matching the matcher and returns the allow decision). Either alone should suppress the prompts; both are present so that if Cowork's host-side permission scoping respects one but not the other, the user is still covered.

Deny rules in user settings still take precedence over both mechanisms (per [Configure permissions](https://code.claude.com/docs/en/permissions) docs). If the user has explicitly denied any of these three tools, the plugin's allow rules will not override that.

### Effect on users

When `memoforge-0.5.2.zip` is installed in Cowork and the plugin is enabled, the next `/memoforge:memo` run should produce zero permission prompts for `mcp__cowork__*` artifact tools. The user sees the same chat scroll "Updated artifact: ..." strips and sidebar card refreshes as v0.5.1 — minus the modal interruptions.

### Verification

- `python -m unittest discover -s scripts/tests` — all 115 tests still pass (no scripts changed).
- Hook smoke test (Git Bash): `echo '{"tool_name":"mcp__cowork__update_artifact"}' | python hooks/auto_approve_cowork.py` → returns valid allow-decision JSON. With `tool_name=Bash` → returns no output.
- Manifest match: `.claude-plugin/plugin.json === README badge === dist/memoforge-0.5.2.zip === git tag v0.5.2`.

## 0.5.1 — 2026-05-25

**Pre-return checklist patches the v0.5.0 instruction-following gap.** First-day v0.5.0 production runs revealed that subagents sometimes skipped the `done` `update_artifact` emission while focused on composing their return summary. Result: the sidebar card stuck on the previous step (e.g. last "issue-N-of-total") instead of advancing to "<agent> — done · <verdict + counts>". The bug was instruction-design: live-progress was a separate appendix section, easily de-prioritised under context pressure. v0.5.1 fixes this with three changes — no functional changes to substantive pipeline behavior.

### Why

User observation on 2026-05-25 (first v0.5.0 real run): two of three Phase 5 researchers (statutory + case-law) finished their substantive work cleanly but did NOT emit the `done` live-progress update; only doctrinal did. Same instruction template across all three — the failure was LLM instruction-following variance, with the "done" emission specifically being the most-skipped because it sits at the END of the agent's work when the LLM is mentally transitioning to "compose return summary". The fix needed to be structural: a clear stop-and-verify checkpoint immediately before the `## Final response` section.

### What changed

- **NEW `## Pre-return checklist` section** added to every instrumented agent file (15 agents: `memo-writer`, 3 researchers, 5 reviewers, `revision-mediator`, `client-readiness-reviewer`, `research-sufficiency-reviewer`, `currency-checker`, `source-pack-builder`, `fact-assumption-analyst`). Placed **immediately before** the existing `## Final response` (or `## Final response to main session`) section. Each checklist:
  - Names the specific `update_summary` tag the agent should have emitted (e.g. `statutes-done`, `mediator-iter<N>-done`, `step=done` for memo-writer).
  - Explicitly says "STOP. Verify the live-progress `done` emission." with a yes/no decision tree.
  - If the agent missed the emission, instructs it to execute the canonical render + `update_artifact` pair NOW, before composing the summary.
  - Includes the original observed-bug rationale ("v0.5.0 production runs showed agents occasionally skipping...") so the agent understands why the checklist exists.
- **Orchestrator-side phase-transition update_artifact promoted to MANDATORY** in `skills/memo/SKILL.md` Phase 1 step 3.5's "downstream responsibility" paragraph. Rewritten as a numbered three-step sequence with explicit Bash + tool-call invocations, treated as a peer of the existing TodoWrite + mark_chapter mantras at every `current_phase` change.
- **No agent functional changes** — same step boundaries, same `update_summary` tags, same step strings, same skip rule (`state.json.config.live_progress_enabled == false` skips everything). Only the instruction-prominence is increased.

### Effect on users

Same v0.5.0 architecture and the same memo output. The sidebar live-progress dashboard now updates RELIABLY at every `done` boundary (per the §Pre-return checklist enforcement) and at every phase transition (per the strengthened SKILL.md mandate). The user-visible signal should now match expectations: every researcher completion produces a strip + card refresh; every reviewer verdict produces a strip + card refresh; every mediator iteration produces a strip + card refresh; the final card lands on the "done" state for the last subagent that ran.

### Verification

- `python -m unittest discover -s scripts/tests` — all 115 tests still pass (no scripts changed).
- Manifest match: `.claude-plugin/plugin.json === README badge === dist/memoforge-0.5.1.zip === git tag v0.5.1`.

## 0.5.0 — 2026-05-25

**Live progress dashboard via subagent-side artifact streaming.** The "Live artifacts" sidebar card now refreshes in real time as the pipeline runs — every heavy subagent emits its own `mcp__cowork__update_artifact` call at its internal step boundaries, and those calls flush to the parent orchestrator's chat scroll in real time (postmortem §9 RESOLVED = STREAMING PASS, 2026-05-25). The user no longer sees 5–40 minutes of chat silence during Phase 5→Phase 12; instead, an "Update artifact" indicator strip appears in chat for every researcher source, every drafted issue, every reviewer verdict, and every mediator decision.

### Why

v0.2.0 attempted live progress via orchestrator-side `update_artifact` calls and was rolled back because those calls buffer to end-of-turn (same failure mode as the Cowork text-buffering bug). The v0.2.0 postmortem (`docs/postmortems/v0.2.0-live-progress.md`) flagged ONE open hypothesis (§9): would calls made from INSIDE a dispatched subagent bypass the orchestrator-turn buffer? The probe dist `memoforge-0.5.0-probe.zip` (developer-only, preserved on disk, README untouched) tested this empirically on 2026-05-25 with explicit 25-second sleeps and a falsifiable user-question framing. Result: STREAMING PASS — the artifact strips and sidebar card refresh DO surface in the parent chat scroll as the subagent works, not buffered to end-of-turn. v0.5.0 productionises that mechanism.

### What changed

- **NEW `scripts/render_live_progress.py`** — the canonical renderer. Reads `state.json` and a `--current-step` string, writes a pretty HTML dashboard with: 13-phase progress bar (current pulsing, completed filled with checkmark color, future grey-outlined), large "current step" line with elapsed-time counter, completed-phases timeline with per-phase durations, and a CSS-only "alive" pulse in the corner. `<meta charset="UTF-8">` is mandatory (v0.2.0 encoding lesson preserved). Atomic write via `.tmp` + rename. 32 unit tests at `scripts/tests/test_render_live_progress.py`.
- **NEW `skills/memo/references/live-progress-contract.md`** — canonical contract for the live-progress channel: lifecycle (mint at Phase 1 step 3.5, subagent updates during work, terminal close at done/failed/cancelled), subagent skip rule (read `state.json.config.live_progress_enabled` first), canonical subagent update pattern, concurrency note for Phase 5 parallel research (last-writer-wins on the HTML, atomic .tmp + rename prevents torn writes), failure-mode table, encoding requirement.
- **`skills/memo/SKILL.md` Phase 1**:
  - NEW **step 3.5** (after visualize precheck): detects `mcp__cowork__create_artifact` / `update_artifact` availability, sets `state.json.config.live_progress_enabled`, mints the master artifact with id `memo-<task_id>-live` and `html_path = <work_dir>/live-progress.html`, populates `state.json.live_progress.{artifact_id, html_path, started_at_iso, phase_started_at_iso, timeline[]}`. Appends `live_progress_precheck_result` and `live_progress_artifact_minted` events. Status-line addition: `; live progress: ✓ — sidebar dashboard active` (or `✗ — not available in this host`).
  - Phase boundary updates (orchestrator-side) at every `current_phase` change: append timeline entry, update phase_started_at_iso, re-render, call `update_artifact`. These calls buffer to end-of-turn — that's fine; subagents inside the new phase provide the live signal.
- **`skills/memo/state-schema.md`** — adds `config.live_progress_enabled` (precheck flag) and the top-level `live_progress: null | { artifact_id, html_path, started_at_iso, phase_started_at_iso, timeline[] }` block with full field-level ownership documentation.
- **11 subagents instrumented** with `update_artifact` calls at their step boundaries (each agent file has a new "Live progress" section + `Bash, mcp__cowork__update_artifact` added to its `tools:` allowlist):
  - **`memo-writer`** — per-issue updates (`Drafting issue 3 of 7 — <issue label>`), plus start / assembling / done. Matches the existing `step=issue-N-of-total` log discipline. Biggest single live-progress win (memo-writer dominates Phase 8 silence).
  - **`statutory-researcher`, `case-law-researcher`, `doctrinal-researcher`** — per-issue updates only (NOT per-search; per-search would flood chat with 10–20 strips per researcher). Phase 5 parallel block becomes visible as the three researchers' alternating step messages refresh the card.
  - **`research-sufficiency-reviewer`, `currency-checker`, `source-pack-builder`** — start + done.
  - **5 reviewers** (`style-reviewer`, `clarity-reviewer`, `logic-reviewer`, `counterargument-reviewer`, `citation-auditor`) — start + done with verdict + blocking count.
  - **`revision-mediator`** — start + per-iteration verdict. State.json mutations remain the mediator's sole-ownership responsibility; live-progress emissions are additive.
  - **`client-readiness-reviewer`** — start + done with verdict + blocking count.
  - **`fact-assumption-analyst`** — start + done (light agent; Phase 1 transitional update).
- **`skills/memo/references/INDEX.md`** — entry for `live-progress-contract.md`; pre-Phase-1 reading list updated to include it; authority hierarchy row updated.

### Effect on users

Same query, same memo output, same wallclock — the user now SEES the pipeline running. A typical Full-mode 5-iteration run produces ~20–35 distinct "Updated artifact" indicator strips in the chat scroll plus continuous sidebar card refreshes throughout the run, instead of the prior single-flush-at-Phase-7.5-then-silence-until-Phase-12 experience.

The substantive pipeline is otherwise unchanged. The skip rule means the pipeline still runs cleanly when Cowork's artifact tools are unavailable — the substantive memo work is never blocked by a live-progress emission. The probe skill (`/memoforge:probe`) and the `probe-subagent-streamer` agent that proved §9 have been removed from the production zip; they remain in `dist/memoforge-0.5.0-probe.zip` for historical record.

### Verification

- `python -m unittest discover -s scripts/tests` — **all 115 tests pass** (83 baseline + 32 new render_live_progress tests). No regressions in the existing 83.
- Manifest match: `.claude-plugin/plugin.json === README badge === dist/memoforge-0.5.0.zip === git tag v0.5.0`.

> Version note: `0.5.0-probe` was the probe build that resolved §9 of the v0.2.0 postmortem. It is preserved on disk as `dist/memoforge-0.5.0-probe.zip` and was never made the current README's recommended install — only this 0.5.0 release is.

## 0.4.0 — 2026-05-25

**Custom style profiles (Style Studio).** Users can now define their own style and formatting rules — from example memos, written rules, or both — and pick the profile when starting a new memo. Profiles are persistent across tasks, scoped to one mode (Brief or Full), and override the built-in `lib/prose-style.md` + `templates/<id>.md` for that run.

### Why

The plugin had two hardcoded sources of style: `lib/prose-style.md` (tone, sentence/paragraph caps, anti-patterns, Risk pattern) and `templates/<id>.md` (document structure). Both reflected one in-house style. Users with a different house style — different citation format, different risk vocabulary, different section ordering, no em-dashes ever, OSCOLA instead of inline brackets — had to either accept the bundled style or maintain a fork. There was no per-user customization path.

### What changed

- **New skill `/memoforge:style`** — single entry point for all profile management (`new` / `list` / `use` / `show` / `delete`). Sub-actions are arguments, not separate skills, so only one command appears in slash autocomplete. Interactive menu when run without arguments; direct sub-action when arguments are provided. Frontmatter `argument-hint` documents both forms.
- **New subagent `style-extractor` (`model: opus`)** — reads example memos (`.docx` via pandoc, `.pdf` and `.md` directly), text rules (inline or path), or both, and writes `prose-style.md` + (conditionally) `template.md` + `meta.json` + `rules.md` into the profile directory. Rules win over example-extracted patterns on conflict; every rule is origin-tagged `(from examples)` / `(from rules)` / `(rule overrides example pattern)`. Sources and Disclaimer are always present in the extracted template (compliance minimum).
- **Profiles stored globally** at `~/.claude/plugin-data/memoforge/profiles/<name>/`, with `default-profile.txt` recording the user's preselected default. Cross-project; cross-platform paths are POSIX-form in `state.json`.
- **One profile = one mode.** The user picks Brief or Full at creation; for both modes, create two profiles. No mode-binding heuristics — explicit user choice.
- **New script `scripts/resolve_style_profile.py`** — canonical write path for profiles. Sub-commands for the skill: `list`, `get-default`, `set-default`, `clear-default`, `validate-name`, `validate-profile`, `delete`, `read-meta`, `resolve-paths`, `init-profile`, `write-meta`. Env var `MEMOFORGE_PROFILES_HOME` overrides the default location (used by tests and power users). 29 new unit tests in `scripts/tests/test_resolve_style_profile.py`.
- **`skills/memo/SKILL.md` Phase 1.5 step 8** — new style-profile resolve. **Zero overhead when the user has no profiles**: nothing is asked, nothing is logged, `config.{style_profile, style_profile_path, prose_style_path, template_path}` are all written as `null`. When at least one profile exists, an `AskUserQuestion` checkpoint asks which profile (default preselected) or "Standard plugin style (built-in)". If the picked profile's `mode_binding` differs from the run's mode, a follow-up checkpoint asks whether to switch mode or use the built-in template only.
- **`state.json.config`** gets four optional fields (all default `null`): `style_profile`, `style_profile_path`, `prose_style_path`, `template_path`. When non-null, the writer and reviewers read the custom files instead of the built-in ones. `template_id` is still always set (mode-bound) so classifier and validator logic remain stable.
- **6 agents patched** to read the new state fields and switch between built-in and custom prose-style/template: `memo-writer`, `style-reviewer`, `clarity-reviewer`, `logic-reviewer`, `counterargument-reviewer`, `revision-mediator`. Each agent's "Custom style profile" section documents which hardcoded checks are suppressed in custom-profile mode and which still apply (structural integrity, grammar, substantive analysis quality are profile-agnostic).
- **`skills/memo/SKILL.md` Phase 9 reviewer dispatch** updated so every reviewer (except `citation-auditor`) receives the path to `state.json` in its prompt — needed to read the new config fields.

### Effect on users

- Users who have never used the Style Studio see no change. `/memoforge:memo` runs exactly as before, with the bundled prose-style and templates.
- Users who run `/memoforge:style new my-firm --examples ./samples/ --mode full` get a profile they can apply to all future memos with `/memoforge:style use my-firm`. The next `/memo` run preselects this profile at the Phase 1.5 checkpoint.
- Cross-project: profiles live in the user home, so a profile created from `~/work/contracts/` examples can be used from `~/work/privacy/` too.
- Confidence: `meta.json.confidence` (0.0-1.0) is computed by the extractor — see the skill output. Below 0.6 the skill prints a warning when set as default.

### Verification

- Unit tests: `python -m unittest discover -s scripts/tests` — 83 tests pass (29 new + 54 existing).
- Smoke (no profiles): `/memoforge:memo "<q>"` with empty `~/.claude/plugin-data/memoforge/profiles/` → Phase 1.5 has no extra checkpoint, identical UX to v0.3.0.
- Smoke (with profile): `/memoforge:style new test --rules "no em-dashes; OSCOLA citations" --mode brief` → `/memoforge:style use test` → `/memoforge:memo "<q>"` → Phase 1.5 shows the new style checkpoint with `test` preselected.
- Manifest match: `.claude-plugin/plugin.json` version === README badge === git tag `v0.4.0` === dist zip filename.

## 0.3.0 — 2026-05-25

**Per-agent model assignment.** All 15 subagents now declare an explicit `model:` in their frontmatter. Previously every agent silently inherited the session model, so a single Sonnet/Opus choice applied uniformly across creative drafting, mechanical structuring, and pattern-detection — overspending on simple tasks and underspending on hard ones.

> Version note: 0.2.0 was reserved for the live-progress sidebar attempt (rolled back, see `docs/postmortems/v0.2.0-live-progress.md`); the on-disk `dist/memoforge-0.2.0.zip` is the artifact of that failed iteration and was never republished. To avoid clashing with that filename, the next user-facing release after 0.1.1 is 0.3.0.

### Why

The pipeline has three distinct intelligence tiers:

1. **Creative and adversarial work** — drafting the memo, mediating reviewer conflicts, building intake assumptions, hunting contrary authority, synthesising doctrinal commentary, and grounding citations at the writer's depth. Errors here are the most expensive ones in the pipeline (a bad intake assumption silently corrupts every downstream phase; a shallow counterargument review ships a fragile memo).
2. **Search and structured QA** — running MCP queries against statutes/case-law sources, gating research sufficiency, checking currency, building the source pack, and the three isolated draft reviewers (logic/clarity/style). These are structured, schema-constrained tasks where Sonnet is reliable.
3. **None** — Haiku is deliberately not used in this release. The cost-savings vs. Sonnet on legal-nuance tasks did not justify the regression risk.

### What changed

- **`model: opus` added to 6 agents** — `memo-writer` (creative core), `revision-mediator` (conflict resolution + exit decision), `fact-assumption-analyst` (intake judgment), `counterargument-reviewer` (adversarial reasoning), `doctrinal-researcher` (cross-source synthesis with conflicting positions), `citation-auditor` (grounding at writer's depth — needed to catch subtle source-drift, not just missing citations).
- **`model: sonnet` added to 9 agents** — `statutory-researcher`, `case-law-researcher`, `research-sufficiency-reviewer`, `currency-checker`, `source-pack-builder`, `logic-reviewer`, `clarity-reviewer`, `style-reviewer`, `client-readiness-reviewer`.
- **`lib/revision-loop.md` synchronised** with the new reality: the per-reviewer model column now matches the agent frontmatter (was: Haiku for logic/clarity/style, Sonnet for citations/counterarguments; now: Sonnet for the three isolated reviewers, Opus for the two augmented reviewers). The "reviewer takes too long" edge-case note was rewritten to recommend `CLAUDE_CODE_SUBAGENT_MODEL` override rather than editing frontmatter as a hot-fix.
- **No changes** to `skills/memo/SKILL.md`, `skills/continue/SKILL.md`, `skills/status/SKILL.md` — these orchestrators run in the main session and must inherit the user's session model. Agent-tool dispatch calls (`Agent(subagent_type=...)`) in `skills/memo/SKILL.md` lines 946–950 are also untouched; the frontmatter is the single source of truth for per-agent model selection.

### Effect on users

A typical Full-mode run now uses Opus on 6 of 15 agents and Sonnet on 9, instead of the user's session model uniformly. Expect higher cost per memo when the session is on Sonnet (because 6 agents are bumped up to Opus) but better intake/counterargument depth and grounding accuracy. Users on Opus sessions see partial cost relief (9 agents bumped down to Sonnet) without quality regression on those agents.

To override the per-agent assignment for a single run, set `CLAUDE_CODE_SUBAGENT_MODEL` in the environment before launching `/memoforge:memo`.

- Manifest match: `.claude-plugin/plugin.json` version === README badge === git tag `v0.3.0` === dist zip filename.

## 0.1.1 — 2026-05-22

**Hide internal pipeline modules from slash-command autocomplete.** Moves three "skills" out of `skills/` into a new `lib/` directory so they no longer register as `/memoforge:<name>` commands. Pipeline behaviour is unchanged.

### Why

`/memoforge:` autocomplete listed six commands, but only three (`memo`, `continue`, `status`) were user-facing entry points. The other three (`legal-memo-prose-style`, `legal-memo-docx-render`, `revision-loop`) were internal modules that `/memo` loaded via `Read` or invoked via `Bash` — they never needed a user-typed slash form. Showing them in autocomplete confused users into picking the wrong command.

Claude Code plugin SDK has no `hidden` / `user_invocable` frontmatter flag — the loader scans `skills/` and registers every `SKILL.md` as a slash command. The only reliable mechanism to remove a skill from slash autocomplete is to move it out of `skills/`. `lib/` is the conventional name for "shared modules used by the main code"; the mental model becomes "`skills/` is what the user types; `lib/` is what the pipeline reads".

### What changed

- **Moved.** `skills/legal-memo-prose-style/SKILL.md` → `lib/prose-style.md`. `skills/revision-loop/SKILL.md` → `lib/revision-loop.md`. `skills/legal-memo-docx-render/` → `lib/docx-render/` (SKILL.md → README.md as maintainer doc; `scripts/md_to_docx.py` keeps its location relative to the module root, now at `lib/docx-render/scripts/md_to_docx.py`).
- **Frontmatter stripped** from `lib/prose-style.md`, `lib/revision-loop.md`, `lib/docx-render/README.md` — they are no longer skills, so the `name:` / `description:` fields would be misleading.
- **Path references updated in 18 files.** `skills/memo/SKILL.md`, `skills/continue/SKILL.md`, 7 agents (`memo-writer`, `revision-mediator`, `client-readiness-reviewer`, `style-reviewer`, `clarity-reviewer`, `logic-reviewer`, `counterargument-reviewer`), 3 templates (`classical-memo`, `executive-brief`, `research-summary-only`), 3 reference docs (`skills/memo/references/INDEX.md`, `operating-contract.md`, `pipeline-contract.md`), `README.md` (skills table split into "Skills" and "Internal library modules (`lib/`)"), `scripts/tests/test_md_to_docx_banner.py` (hardcoded `SCRIPT` path constant), and the Python script's own docstring comments.
- **`__pycache__/`** removed from the moved scripts directory (was a build artifact, never should have been on disk).
- **CHANGELOG entries for prior versions** left at their original `skills/legal-memo-prose-style/SKILL.md` etc. paths — historical accuracy. Only this 0.1.1 entry uses the new `lib/` paths.

### Effect on users

`/memoforge:` autocomplete now shows three commands (`memo`, `continue`, `status`) instead of six. Pipeline behaviour is unchanged — `/memo` still loads `lib/prose-style.md` at the same Phase 3 and Phase 8 reads, still calls `lib/docx-render/scripts/md_to_docx.py` at the Phase 11 export step, still references `lib/revision-loop.md` in Phase 9.

If a user had built muscle memory for `/memoforge:legal-memo-prose-style` or `:revision-loop` to peek at internal methodology, they now open `lib/prose-style.md` or `lib/revision-loop.md` in the file viewer instead.

### Verification

- `python3 -m unittest discover -s scripts/tests` — **54/54 OK** (11.7s, no code-behaviour changes).
- `python lib/docx-render/scripts/md_to_docx.py` smoke-run against synthetic markdown — exit 0, valid `.docx` produced.
- Grep across the whole plugin for `skills/legal-memo-prose-style`, `skills/revision-loop`, `skills/legal-memo-docx-render` returns **0 matches in production code** (CHANGELOG retains historical references by design).
- Manifest match: `.claude-plugin/plugin.json` version === README badge === git tag `v0.1.1` === dist zip filename.

## 0.1.0 — 2026-05-22

**First public release.** Promotes the plugin from internal `0.0.x` iterations to a stable, documented `0.1.0` baseline suitable for external installation.

### Why

The `0.0.x` series captured 52 iterative refinements driven by internal testing against real legal memos (writer-side, reviewer-coverage, cross-cutting quality bundles). At `0.0.52` the plugin reached production-ready quality: six bundle overhauls landed in 0.0.52 closed the last document-global gaps (cross-section consistency, recommendation concreteness, counter-argument completeness, heading discipline, writer state visibility, length proportionality). `0.1.0` is the same code with a rewritten public-facing README, a new MIT LICENSE, and a clean release artifact for the GitHub Releases page.

### What changed

- **`README.md`** — full rewrite for public consumption. New sections: at-a-glance pipeline diagram, agent table (what each of the 15 subagents does), skills table, mode comparison (Brief vs Full), three-checkpoint UX walkthrough, output-folder resolution, MCP/web-search policy summary, customization, known limitations, repo layout.
- **`LICENSE`** — MIT license added.
- **`.claude-plugin/plugin.json`** — version bumped `0.0.52` → `0.1.0`.
- **`dist/memoforge-0.1.0.zip`** — clean release build, forward-slash paths (Cowork plugin loader compatible).
- No agent prompts, skill methodology, or validator schemas changed in this release — `0.1.0` is purely the public-release packaging of `0.0.52`.

### Verification

- `python3 -m unittest discover -s scripts/tests` — 54/54 OK (no code changes since 0.0.52).
- Zip integrity: extracted `dist/memoforge-0.1.0.zip` and confirmed forward-slash separators throughout.
- Manifest match: `.claude-plugin/plugin.json` version === README badge === git tag `v0.1.0` === dist zip filename.

## 0.0.52 — 2026-05-22

**Comprehensive quality overhaul — six bundles addressing document-global gaps that per-paragraph reviewers cannot catch. Defense-in-depth at writer + reviewers + client-readiness safety net for each rule.**

### Why

Three independent audits (writer-side, reviewer-coverage, cross-cutting) found six bundles of gaps preventing the plugin from consistently producing "high-class, clear, logical" memos. Sentence-length and paragraph-length discipline (0.0.47–0.0.51) addressed individual prose units but left document-global defects un-checked: risk-score drift across sections, vague recommendations, missing inline contrary authority at medium verdicts, headings-as-questions, writer ignoring state.json mode/template/assumptions-accepted, asymmetric Analysis depth. The user-provided test memo `memo-20260521T131752Z` shipped with multiple instances of each defect type.

### What changed — by bundle

**Bundle A — Cross-section consistency.** New `## Cross-section consistency` section in `skills/legal-memo-prose-style/SKILL.md`. Rules: (1) risk score identical in Exec Summary bullet, Analysis Risk line, and Conclusion item for the same subsection — no drift; (2) every Exec Summary bullet ends with `(§ N)`, every Conclusion item starts with `§ N.M:`; (3) bijection between analytical subsections and Exec Summary bullets / Conclusion items (no orphans); (4) Recommendation matrix labels every column/row with its subsection number; high-residual-risk options conflicting with `Risk: high` blocker verdicts must be labelled `consequence of ignoring the recommended path, not a viable option`. New writer self-check rule. New `logic-reviewer` blocking check (content layer: risk-score drift, orphans, matrix reconciliation). New `style-reviewer` blocking check (format layer: `(§ N)` cross-references present). New template rules in classical-memo and executive-brief.

**Bundle B — Recommendation concreteness.** New `### Recommendation concreteness (Beat 4)` subsection in prose-style SKILL inside the Risk subsection pattern. Rule: every Risk-line recommendation names an action verb (specific operational step), a condition/trigger, and an owner/accountable function. Generic verbs alone (`consider`, `ensure`, `review`, `evaluate`, `assess`, `monitor`, `be aware of`) do NOT count as action verbs. New writer self-check. New blocking checks in `style-reviewer`, `clarity-reviewer`, AND `client-readiness-reviewer` (full defense-in-depth incl. Brief-mode safety net). New template rules.

**Bundle C — Counter-argument completeness.** New `### Counter-argument framing` subsection in prose-style SKILL. Three rules: (1) `Risk: medium` / `undetermined` verdicts MUST name contrary authority inline in the justification sentence(s) and explain why analysis stands; (2) where Analysis discusses a counter-argument and resolves "does not prevail", the Risk line MUST state explicit trigger conditions that would activate the counter-argument; (3) every Material Assumption in Conclusion is either linked to a specific Open Question (with "if answered as X, re-evaluate § N" note) or explicitly labelled "immaterial — does not affect any conclusion". New writer self-check. New `counterargument-reviewer` blocking checks (`overconfidence` for medium-without-contrary-authority; `understated_risk` for counter-arg-without-triggers). New `logic-reviewer` blocking check for Material Assumption ↔ Open Question mapping. New template rules.

**Bundle D — Heading discipline.** New `### Heading discipline` subsection in prose-style SKILL §Document structure. Rules: (1) all headings (H1/H2/H3) are noun phrases — not questions ("Does X apply?"), not imperatives ("Consider the Y risk"); (2) hierarchy H1 → H2 → H3 only, no H4 in analytical sections, no skip jumps. New writer self-check. New `style-reviewer` blocking checks. New template rules.

**Bundle E — Writer state visibility.** `agents/memo-writer.md` §Inputs (v1) expanded to make `state.json` a mandatory input with explicit extraction list: `mode`, `config.template_id`, `config.max_iterations`, `intake.assumptions_accepted`, `language`. New writer rule `State-aware inputs` enumerates the obligations: mode-specific compression, template-specific structure, currency-report.json `blocking[]` source-ID avoidance, and the assumption-disclosure obligation when `intake.assumptions_accepted == false` (a sentence in Context paragraphs disclosing that intake assumptions were not user-confirmed). §Inputs (vN) extended with optional raw-reviewer-JSON read for context-disambiguation (mediator output remains primary). `skills/memo/SKILL.md` Phase 8 dispatch updated to pass `state.json` explicitly and name the fields the writer extracts. New `client-readiness-reviewer` blocking check for the assumptions-not-accepted disclosure (it reads `state.json` per its inputs list).

**Bundle F — Polish.** Three additions: (1) `clarity-reviewer` new blocking check for per-section length proportionality (any single analytical subsection > 50% of total Analysis word count is structural imbalance); (2) `style-reviewer` new blocking check for header-block query scope clarity (memo with ≥3 analytical subsections must signal multi-issue scope in the Query header line); (3) `agents/memo-writer.md` new rule for currency-blocking absence disclosure (when a canonical source in the memo's topic is on the `blocking[]` list and therefore not cited, surface a one-sentence acknowledgment in Sources or the relevant subsection to prevent reader confusion about the famous-case absence).

### Verification

- `python3 -m unittest discover -s scripts/tests` — 54/54 OK expected (prompt-level changes only).
- Grep audit: each bundle's canonical rule appears in `skills/legal-memo-prose-style/SKILL.md` + `agents/memo-writer.md` + ≥1 reviewer + ≥1 template + this CHANGELOG entry.
- Dry-run against `memo-20260521T131752Z/drafts/v3.md`:
  - **A**: Section 7 Exec Summary "Risk: high. launch blocker" vs Recommendation matrix "Aggressive: launch anyway" → blocking under matrix-reconciliation rule.
  - **B**: "Verify DPF status pre-launch" lacks owner → blocking under vague-recommendation rule.
  - **C**: Article 22 Section 4 Risk line ("Risk: medium … fact-fragile") would carry triggers but the inline-on-Risk-line discipline is now mandatory (currently they sit in a paragraph above).
  - **D**: all v3 headings comply — no over-fire.
  - **E**: `state.json.intake.assumptions_accepted == false` (per the user's state) — new client-readiness-reviewer check would flag the missing Context disclosure.
  - **F**: Section 3 word count is ~30% of Analysis — within 50% cap; passes.
- No schema changes to `validate_review_json.py` or `validate_state.py` — new findings ride existing `blocking_issues[]` arrays with established `attack_vector` enum values (`overconfidence`, `understated_risk`) for counter-argument-reviewer additions.

## 0.0.51 — 2026-05-22

**Enforce paragraph-length discipline as a blocking issue — closes the "wall of text" gap that the sentence cap alone could not catch.**

### Why

After 0.0.47 made sentence length a blocking issue (40 words / 2 independent ideas), it became clear the sentence cap alone does not deliver readable prose: a paragraph can satisfy every sentence rule individually yet still be a 5-sentence / 270-word brick of dense legal analysis. The user pointed at one such paragraph in `memo-20260521T131752Z` Section 3.2 (Article 6(1)(f) analysis) — 5 sentences, ~270 words, three different cumulative-condition tests stacked into one paragraph, three citation clusters, no visual break for the reader.

No prose-style file, no reviewer prompt, and no template currently constrained paragraph length. The templates said "1-3 short paragraphs" qualitatively but no reviewer checked the cap, so "short" drifted into "as long as I want as long as no single sentence exceeds 40 words".

User decision: same defense-in-depth pattern as the sentence rule (writer self-check + both reviewers + client-readiness as Brief-mode safety net) with a tight threshold of **3 sentences and 100 words** per paragraph.

### What changed

- **`skills/legal-memo-prose-style/SKILL.md`** — new top-level `## Paragraph structure — short, single-idea, easy to skim` section parallel to `## Sentence structure`. Includes a `### Hard limits` subsection with the 3-sentences / 100-words cap, the exemption list (blockquote, bullets, numbered list items, headings, titles, table cells), and the enforcement contract (style + clarity + client-readiness all treat violations as blocking).
- **`agents/memo-writer.md` §Rules** — new `Paragraph-length self-check (hard rule, blocking at review)` bullet added immediately after the existing sentence-length self-check. Writer must scan every authored prose paragraph per-section and split anything over the cap. Explicitly names the three reviewers that enforce it.
- **`agents/style-reviewer.md` §Sentence and tone discipline** — new `Long packed paragraphs (blocking)` check added next to the existing `Long packed sentences` check. Same blocking-issues output shape: paragraph quoted as `<first 15 words> … <last 10 words>` with a concrete split suggestion.
- **`agents/clarity-reviewer.md` §What you check** — new `Paragraph length (blocking)` check parallel to the existing `Sentence length` check. Framed around the target reader (non-lawyer business stakeholder) — "wall of text" defeats accessibility.
- **`agents/client-readiness-reviewer.md` §Checks** — new `Paragraph-length cap (final safety net)` check parallel to the existing `Sentence-length cap`. Same Brief-mode rationale: Brief disables style + clarity, so client-readiness is the only post-draft gate for paragraph discipline in Brief.
- **`templates/classical-memo.md` and `templates/executive-brief.md` §Rules** — new `Paragraph-length cap (hard, blocking at review)` bullet added after the sentence-length cap. Executive-brief notes that the cap rarely binds for the already-compressed template but is enforced uniformly.

### Verification

- `python3 -m unittest discover -s scripts/tests` — 54/54 OK (prompt-level changes only; no Python or schema changes).
- Targeted re-grep: paragraph rule appears in 7 files (prose-style SKILL, memo-writer, style-reviewer, clarity-reviewer, client-readiness-reviewer, classical-memo, executive-brief).
- Manual dry-run against `memo-20260521T131752Z/drafts/v3.md` §3.2 paragraph 3 (the 5-sentence, ~270-word "EDPB frames the same test" paragraph): under the new prompts both `style-reviewer` and `clarity-reviewer` would route this to `blocking_issues[]`, the mediator passes it through, and the writer splits it on the next revision.

## 0.0.50 — 2026-05-22

**Numbered lists get the same paragraph overrides as bullets, and both disable Word's `contextualSpacing` so the 6pt after-spacing applies between items.**

### Why

After 0.0.49 unified bullet indents to `<w:ind w:left="720"/>`, two follow-ups surfaced:

1. **Numbered lists were inconsistent with bullets.** 0.0.49 kept numbered lists on the style default (left=360 with `firstLine=0`) — visually narrower than the deeper bullet indent. The user pointed out they should match, so the renderer's output looks the same regardless of whether the markdown uses `-` or `1.`.
2. **Items of the same list style were too tight.** Word's built-in `ListBullet` and `ListNumber` styles ship with `<w:contextualSpacing/>` set in `styles.xml`, which is the "Don't add space between paragraphs of the same style" checkbox in the Paragraph dialog. The result is 0pt spacing between consecutive list items even though `space_after = Pt(6)` is set. The user wants normal 6pt after-spacing between list items, so this style flag has to be overridden at the paragraph level.

### What changed

- **`skills/legal-memo-docx-render/scripts/md_to_docx.py`**:
  - New helper `_disable_contextual_spacing(paragraph)` injects `<w:contextualSpacing w:val="0"/>` into the paragraph's `pPr` in the correct schema slot (after `w:ind`, before `w:jc`). This overrides the inherited `contextualSpacing=true` from Word's built-in list styles and restores the 6pt after-spacing between items.
  - `add_list_item` no longer branches on `ordered`: both bullets and numbered lists now receive the same three paragraph overrides:
    1. `left_indent = INDENT_LEFT_LIST` (720 DXA)
    2. `_clear_inherited_tab(p, 360)` (clear inherited tab at the default marker position)
    3. `_disable_contextual_spacing(p)` (turn off `contextualSpacing` flag)
  - `first_line_indent` is no longer set explicitly for numbered lists either — the inherited hanging=360 from `ListNumber` stays in effect, so the number sits at 360 DXA and wrapped text starts at 720 DXA, exactly mirroring bullets.
- **`skills/legal-memo-docx-render/SKILL.md` §Paragraph types** — bullet and numbered rows rewritten so both reference the same `<w:ind>` + tab clear + `contextualSpacing="0"` triplet. The note "Same paragraph overrides as bullets" makes the parity explicit for future maintainers.

### Verification

- `python3 -m unittest discover -s scripts/tests` — 54/54 OK (prompt-level + XML-injection changes; no Python schema or state.json changes).
- Re-rendered `memo-20260521T131752Z/drafts/v3.md` and inspected the output XML against the source draft (1 Executive Summary section + Material assumptions + Open questions + Sources = 25 bullets, 15 numbered items):
  - **Bullets**: 25/25 carry `w:left="720"`, tab clear at 360, `contextualSpacing="0"`, `jc=both`.
  - **Numbered**: 15/15 carry the same four attributes.
  - Element order in `pPr` is schema-correct: `pStyle → spacing → tabs → ind → contextualSpacing → jc`.

## 0.0.49 — 2026-05-22

**Match the canonical bullet indent: `<w:ind w:left="720"/>` + tab clear at 360, applied on top of `ListBullet` style.**

### Why

Inspection of `memo-20260521T131752Z-gdpr-ai-support-transcripts/memo-gdpr-ai-support-transcripts.docx` showed the user had manually edited ONE bullet (in `## 1. Executive summary`) to add `<w:ind w:left="720"/>` and `<w:tab w:val="clear" w:pos="360"/>` on top of the inherited `ListBullet` style. The other 24 bullets in the same docx retained `md_to_docx.py`'s default output (no `w:left` override, just `w:firstLine="0"`). The user pointed at the edited bullet as the canonical visual style and asked the renderer to apply it everywhere.

Default `python-docx` rendering of `add_paragraph(style="List Bullet")` inherits `<w:ind w:left="360" w:hanging="360"/>` from `numbering.xml`. The marker sits at the left margin, wrapped text at 360 DXA. The Cowork visual spec puts the marker deeper (at 360 DXA, after a 0.25" gap from the margin) and wrapped text at 720 DXA, so bullets are visually distinct from body paragraphs (whose first-line indent is 630 DXA).

### What changed

- **`skills/legal-memo-docx-render/scripts/md_to_docx.py`**:
  - New constant `INDENT_LEFT_LIST = Cm(1.27)` (720 DXA = 0.5") with explanatory comment.
  - New helper `_clear_inherited_tab(paragraph, pos_dxa)` that injects `<w:tabs><w:tab w:val="clear" w:pos="N"/></w:tabs>` into the paragraph's `pPr` in the correct schema position (before `w:ind`). Used to clear the inherited tab at 360 DXA so wrapped lines do not snap back to the old marker position.
  - `add_list_item` now branches on `ordered`:
    - **Bullets (`ordered=False`)**: applies `left_indent=INDENT_LEFT_LIST`, calls `_clear_inherited_tab(p, 360)`. Does NOT touch `first_line_indent` so the hanging=360 from `ListBullet` style stays in effect — marker at 360 DXA, wrapped text at 720 DXA. Matches the user's edited bullet byte-for-byte (minus auto-added spacing attributes that are inert).
    - **Numbered lists (`ordered=True`)**: unchanged. Keeps `first_line_indent=Cm(0)`, inherits left=360 from style. Mirrors the Sources section in the source docx where the user did NOT override.
- **`skills/legal-memo-docx-render/SKILL.md` §Paragraph types** — spec-table rows for bullet and numbered list rewritten to document the new override pattern explicitly, with the exact OOXML attributes a future maintainer needs to reproduce or audit.

### Verification

- `python3 -m unittest discover -s scripts/tests` — 54/54 OK.
- Re-rendered the source draft `memo-20260521T131752Z/drafts/v3.md` with the new code and inspected the output XML:
  - **25/25 ListBullet paragraphs** now carry `<w:ind w:left="720"/>`. (Previously: 1/25, only the user's manual edit.)
  - **25/25 carry `<w:tab w:val="clear" w:pos="360"/>`.** (Previously: 1/25.)
  - All bullets retain `<w:jc w:val="both"/>` (justified) and the standard Arial 12pt run formatting.
  - Numbered list (Sources section) unchanged — still uses default left=360 with `<w:ind w:firstLine="0"/>`.

## 0.0.48 — 2026-05-22

**Unify the section-structure contract for `classical-memo`; enforce Executive Summary bullets-only discipline.**

### Why

Same user-generated memo as 0.0.47 (`memo-20260521T131752Z-gdpr-ai-support-transcripts`) shipped with two more structural defects that v0.0.47 did not catch:

1. **Facts mixed into `## 1. Executive summary`.** Two prose paragraphs (the company's SaaS facts; the transcript / assumption details) followed the Exec Summary bullets within Section 1, rather than living in the prescribed `## 3. Facts, assumptions and limitations` section or in the unnumbered Context paragraphs above `## 1.`. The memo had no separate Facts section at all.
2. **Exec Summary bullets too long (4 sentences each).** Each bullet was effectively a small analytical paragraph with `Risk: <level>` appended, indistinguishable in shape from body paragraphs.

Root cause: **four different files specified four conflicting structures** for `classical-memo`:

| File | What it said |
|------|--------------|
| `templates/classical-memo.md` | 9 sections incl. Exec Summary, Background, Facts, Analysis. |
| `agents/memo-writer.md` (Memorandum structure list, lines 60-72) | 7 sections, **no Exec Summary, no Facts**. |
| `agents/memo-writer.md` (worked skeleton, lines 76-129) | Started numbered sections at `## 1. Background and definitions`. |
| `agents/memo-writer.md` (line 138 deviation note) | `## 1. Exec Summary` then Background then Analysis at `## 2+` — **no Facts mentioned**. |

The writer faithfully resolved the conflict by skipping the disputed sections (Context and Facts) and folding their content into Section 1 prose tail. No reviewer caught this because no reviewer checked section structure beyond the four-beat Risk pattern inside analytical subsections.

### What changed

- **`agents/memo-writer.md` §Memorandum structure (was lines 60-72)** — rewritten as a 9-item authoritative list for classical-memo, with explicit numbered-vs-unnumbered marking. Context paragraphs are unnumbered and sit between the Header block and `## 1.`. `## 1. Executive Summary` is bullets-only (3-5 bullets, each ≤ 2 sentences and ≤ 40 words, no prose). `## 2. Background and definitions` is optional. `## 3. Facts, assumptions and limitations` is **required**. Analytical subsections start at `## 4.` (or `## 3.` if Background is skipped).
- **`agents/memo-writer.md` worked skeleton (was lines 74-129)** — replaced with a skeleton showing the new numbering, an explicit `## 1. Executive Summary` block with bullets-only example, an explicit `## 3. Facts, assumptions and limitations` block, and analytical subsections starting at `## 4.`. The skeleton no longer contradicts the structure list.
- **`agents/memo-writer.md` classical-memo deviation note (was line 138)** — simplified to point at the new skeleton and explicitly list the required numbered sections with the "if Background skipped" renumbering rule.
- **`skills/legal-memo-prose-style/SKILL.md` §Document structure** — expanded from 7 to 9 sections to match the template. Adds Executive Summary (classical-memo only) and Facts/assumptions/limitations entries. Clarifies which sections are numbered vs unnumbered and how numbering shifts when Background is skipped.
- **`templates/classical-memo.md` §Required sections** — Section 4 (Executive Summary) instruction rewritten to say "bullets ONLY, no prose, each bullet ≤ 2 sentences and ≤ 40 words". §Rules expanded with two new blocking rules: (a) Executive Summary discipline (no prose in `## 1.`) and (b) Facts section required.
- **`agents/style-reviewer.md` §Structural elements** — two new blocking checks:
  - **Executive Summary content discipline.** Reviewer detects `**Template:** classical-memo` in the header block; if present and `## 1. Executive Summary` exists, any body paragraph inside that section is a blocking defect (must move to Context or Facts). Each Exec Summary bullet must also be ≤ 2 sentences and ≤ 40 words (the 0.0.47 §Sentence structure Hard limits rule applied per bullet).
  - **Facts section presence.** Classical-memo must have a `## N. Facts, assumptions and limitations` section. Missing Facts is blocking.

### Verification

- `python3 -m unittest discover -s scripts/tests` — 54/54 OK (prompt-level changes only; no Python or schema changes).
- Grep `worst 1-2 offenders per memo as non-blocking` and `sentences >40 words with three or more subordinate clauses → flag` — zero matches outside CHANGELOG history.
- Manual dry-run against the offending memo `memo-20260521T131752Z`: under the new style-reviewer prompt, v3 Section 1 would now produce TWO blocking issues — "prose paragraph inside `## 1. Executive Summary` (move to `## 3. Facts, assumptions and limitations` or Context)" and "Facts section missing" — both reach the writer via the mediator.

## 0.0.47 — 2026-05-22

**Enforce sentence-length discipline as a blocking issue — fixes the "approved memo with 88-word sentences" gap.**

### Why

User-generated memo `memo-20260521T131752Z-gdpr-ai-support-transcripts` shipped `final_status: approved` with multiple 80-90 word sentences chaining 3+ independent ideas via `and that …, and that …` — exactly the construction `skills/legal-memo-prose-style/SKILL.md §Sentence structure` says to avoid. The trace through the review artefacts showed the failure was systemic, not a single agent miss:

1. `clarity-reviewer.md` detected `>40 words with 3+ subordinate clauses` but routed it to `nice_to_have[]`.
2. `style-reviewer.md` flagged long packed sentences only as `non-blocking` (worst 1-2 per memo); promotion to blocking required `>5 in one section`.
3. `revision-mediator.md` drops every `nice_to_have` finding before handoff to the writer (a sound policy for genuine cosmetics).
4. The writer therefore never received a "split this sentence" instruction. v1 → v2 → v3 left the 88-word Section 4 sentence intact even though the mediator's "Ignored" section explicitly noted it on all three iterations.

The fix is defense in depth at a hard threshold (40 words / 2 independent ideas) — prevention at the writer plus enforcement at both reviewers.

### What changed

- **`skills/legal-memo-prose-style/SKILL.md` §Sentence structure** — added a new `### Hard limits` subsection naming the 40-word / 2-idea cap, the verbatim-quote exemption, and the enforcement contract (style + clarity treat violations as blocking, not nice-to-have).
- **`agents/memo-writer.md` §Rules** — new `Sentence-length self-check (hard rule)` bullet added before the house-style bullet. Writer must scan every authored sentence per-section and split anything over the cap before moving to the next section. The house-style bullet now points explicitly at `§Sentence structure Hard limits` so the reference is not ambiguous.
- **`agents/style-reviewer.md` Sentence and tone discipline** — `Long packed sentences` rule rewritten. Was "flag worst 1-2 as non-blocking; >5 in section as blocking". Now: any sentence >40 words OR chaining >2 independent ideas is a `blocking_issues[]` entry with the offending sentence quoted and a concrete split suggestion. Verbatim source quotes exempted.
- **`agents/clarity-reviewer.md` What you check** — `Sentence length` rule rewritten. Was `→ flag` (defaulted to `nice_to_have`). Now: `blocking_issues[]` with verbatim quote and split suggestion. Same threshold as style-reviewer (40 words OR 3+ subordinate clauses). Verbatim source quotes exempted.
- **`templates/classical-memo.md` and `templates/executive-brief.md` §Rules** — new `Sentence-length cap` bullet added so the cap is visible at template level, not only inside the prose-style skill. Existing "Short declarative sentences" guidance retained.
- **`agents/client-readiness-reviewer.md` §Checks** — added a `Sentence-length cap (final safety net)` check. Closes a Brief-mode gap: Brief runs only `logic` + `citations` + `counterarguments` (style and clarity are disabled), so without this addition Brief mode had no enforcement of sentence discipline. The client-readiness reviewer is the only post-draft prose gate in Brief; in Full mode it is a redundant third line of defense after style + clarity. Violations are emitted as `verdict: needs_final_polish` (the writer can split sentences in a single polish pass — no new research needed). Same exemption for verbatim source quotes.

### What did NOT change

- **Mediator's `Ignore all nice_to_have` policy** — unchanged. Long-sentence violations are not filtered now because they no longer land in `nice_to_have[]`; they land in `blocking_issues[]` and reach the writer through the existing path.
- **No new Python pre-check or word-counter script.** LLM reviewers can count words; a Python guard would be redundant maintenance.
- **No new reviewer kind.** Existing `style` + `clarity` set already owns prose; adding a third would inflate the mediator surface.
- **`md_to_docx.py` and the export pipeline** — untouched. This is a prompt-level fix only.

### Verification

- `python3 -m unittest scripts.tests.test_md_to_docx_banner` — still 4/4 green (no Python or schema changes).
- Targeted re-grep for the old rule strings (`worst 1-2 offenders per memo as non-blocking`, `sentences >40 words with three or more subordinate clauses → flag`) returns zero hits outside CHANGELOG history.
- Manual dry-run against `memo-20260521T131752Z`'s `drafts/v3.md` Section 4 88-word sentence: under the new prompts both reviewers route it to `blocking_issues[]`, the mediator passes it through, and the writer is told to split.

## 0.0.46 — 2026-05-22

**Rename the two confusingly-named style skills to disambiguate prose vs. docx.**

### Why

The plugin shipped two skills with near-identical names (`legal-memo-style` and `legal-memo-house-style`) and overlapping `description:` fields. Both shared the `legal-memo-` prefix and the word `style`; the first was about docx rendering (Arial 12pt, margins, banners) and the second was about prose conventions (tone, four-beat Risk pattern, anti-AI-tells). They cross-referenced each other in the body, but at the skill-picker level the names were indistinguishable. Users (and the model itself, when auto-invoking) could not tell which one to read for which purpose.

### What changed

- `skills/legal-memo-style/` → **`skills/legal-memo-docx-render/`** (visual / docx rendering — invokes `scripts/md_to_docx.py`).
- `skills/legal-memo-house-style/` → **`skills/legal-memo-prose-style/`** (prose playbook — tone, structure, reviewer-conflict priorities).
- Both `name:` frontmatter fields, the H1 of the docx-render SKILL.md, and the cross-references inside both SKILL.md bodies updated to the new names.
- Both `description:` strings rewritten so each one explicitly names its sibling skill with a "not this" clause — fixes the picker-collision problem.
- Path strings updated across `agents/memo-writer.md`, `agents/revision-mediator.md`, `agents/client-readiness-reviewer.md`, all three `templates/*.md`, `skills/memo/SKILL.md`, `skills/memo/references/INDEX.md`, `skills/memo/references/pipeline-contract.md`, `skills/memo/references/operating-contract.md`, `skills/continue/SKILL.md`, the docx-render Python script docstring, `scripts/tests/test_md_to_docx_banner.py`, and `README.md`.
- External Cowork-archive reference `legal-memo-style 11.skill` (with space — a literal filename in the user's Cowork org) preserved unchanged everywhere it appears, since that is a different artifact from the plugin's skill.
- CHANGELOG history (entries below this one) preserved unchanged.

### Migration

- No state-schema or runtime behaviour changes. In-flight tasks continue without migration — the new skill directories carry the same content; only the names changed.
- Existing dist zips are not renamed; the 0.0.46 zip (when built) will use the new directory names.

## 0.0.45 — 2026-05-22

**Breaking change: pipeline modes reduced from three to two; output templates reduced from five to two.**

### Why

Analysis of the three-mode pipeline (Quick / Standard / Deep) showed that the Quick→Standard step was a real change (1 vs 3 researchers, 3 vs 5 reviewers, 1 vs 3 iterations, polish off vs on) but Standard→Deep was cosmetic — one extra forced follow-up that overrode the sufficiency reviewer's `sufficient` verdict, one extra polish pass, two more allowed templates. In practice it was a binary preliminary/full decision with a marginal third tier. Bundling research depth, review thoroughness, and output format into one knob also forced compromises (no way to ask for thorough research with short output, or vice versa).

The five templates `executive-brief`, `classical-memo`, `risk-assessment`, `regulatory-analysis`, `cross-jurisdictional` shared the same four-beat Risk subsection pattern; the latter three were variants of `classical-memo` with reordered sections. Carrying all five complicated the classifier and the docx renderer without adding meaningful output diversity.

### What changed

- **Modes**: three → two.
  - **Brief** (was Quick): 1 statutory researcher, 3 reviewers (logic/citations/counterarguments), 1 iteration, no client polish, `executive-brief` template, 1200-word hard cap.
  - **Full** (was Standard / Deep merged): 3 researchers (statutory + case-law + doctrinal when plan flags it), 5 reviewers, 3 iterations, 1 client polish pass, `classical-memo` template.
- **Templates**: five → two. `risk-assessment`, `regulatory-analysis`, `cross-jurisdictional` removed from disk. `executive-brief` and `classical-memo` retained.
- **`config.template_constraint` (object with `forced`/`bounded`/`open` modes and `allowed_set`) removed.** Replaced with a direct `config.template_id` string. The classifier no longer picks the template — it is bound to the mode.
- **`config.targeted_followup_forced` removed.** Deep mode's forced-followup-after-sufficient-verdict override is gone; the sufficiency reviewer's verdict is now honoured verbatim.
- **`max_client_polish` clamped to {0, 1}.** Deep mode's second polish pass is gone.
- **Phase 4a (plan edit categories)**: "Switch template or scope" option removed. To switch templates, cancel and rerun in the other mode.

### Migration (in-flight tasks)

The `continue` skill runs a silent migration on resume:
- `mode: "quick"` → `"brief"`; `mode: "standard" | "deep"` → `"full"`.
- `config.template_constraint` and `config.targeted_followup_forced` are dropped.
- `config.template_id` is backfilled from the mode (or from the removed `template_constraint.template_id`).
- `classification.selected_template_id` of the deleted templates is remapped to `classical-memo`.
- `config.max_client_polish > 1` is clamped to `1`.
- Logged as `state_migrated_legacy_modes` event in `events.jsonl`.

`md_to_docx.py` retains backward-compat for the deleted `template_id` values so already-exported archived state.json entries still render correctly.

### Files removed

- `templates/risk-assessment.md`
- `templates/regulatory-analysis.md`
- `templates/cross-jurisdictional.md`

### Files significantly rewritten

- `skills/memo/references/modes.md` — 2-row matrix, Brief/Full prose.
- `scripts/validate_state.py` — `VALID_MODES`, `MODE_*` constants, cross-field checks.
- `scripts/tests/test_validate_state.py` — 36 tests, all on Brief/Full fixtures.

## 0.0.44 — 2026-05-21

Removes the three remaining post-parallel-Task AskUserQuestion gates inside the drafting + revision + polish block. Combined with the v0.0.43 source-review checkpoint, the pipeline now has exactly **one** user touchpoint between research and final docx — `continue` at source-review — and runs fully autonomously after that.

### Why

v0.0.43 fixed Phase 7.5 (heartbeat → source-review checkpoint with explicit end-of-turn) but left three more AskUserQuestion calls downstream:
- Phase 9 step 6b — end-of-iteration gate (`Continue iter N+1` / `Accept v<N>`)
- Phase 9 step 6c — forced-exit gate (`Continue to client-readiness` / `Export as-is`)
- Phase 10 — pre-polish gate (`Apply polish` / `Export as-is`)

All three fire post-parallel-Task in plugin-skill context and hit the same documented Cowork silent-fail bug (Anthropic issues #26805 / #29773 / #29547 / #33564 / #44776). In production a v0.0.43 Standard-mode run would have hung 3–5 times between source-review and final docx — each time requiring the user to type something to force chat re-render before they could see and click the invisible modal.

User direction (verbatim, in Russian): "вся ревизия одним прогоном, иначе смысл какой в агентах" — the value of multi-agent orchestration is autonomous execution.

### What changed

- **Phase 9 step 6b (end-of-iteration gate) — REMOVED.** When mediator verdict is `needs_revision` and budget remains, the pipeline auto-advances to the next iteration. Writes `revision_gate_choice = "continue"`, emits `gate_auto_advanced` event for audit, dispatches memo-writer for v<N+1>. No user input.
- **Phase 9 step 6c (forced-exit gate) — REMOVED.** When mediator verdict is `forced_exit_on_v<N>_with_remaining_issues`, the pipeline auto-advances to Phase 10 client-readiness (always — no "Export as-is" option). The unresolved-blockers banner from mediator is in `fallback_banners[]` and surfaces in the docx regardless.
- **Phase 10 pre-polish gate — REMOVED.** When client-readiness verdict is `needs_final_polish` and polish is enabled (Standard/Deep) and budget remains, the pipeline auto-applies polish (dispatch memo-writer polish pass + re-run client-readiness reviewer). Loops until verdict is `client_ready` or budget exhausted.

- **Pre-source-review heads-up extended** to set user expectations: after `continue` at source-review, the pipeline runs ~15–40 min of visual silence in chat (drafting + revision + polish + export all in one assistant turn). User monitors via the TodoWrite side panel. Final flush happens at end-of-turn when the docx is written.

- **`gate_auto_advanced` event** added (audit-only, Tier-2). Same `gate_name`/`chosen` shape as `gate_answered` but with `reason: "<mediator_needs_revision_with_budget | mediator_forced_exit | needs_final_polish_with_budget>"`. Fires at each former gate to preserve the audit trail of the decision the orchestrator made automatically.

- **State-schema fields deprecated** but kept for backward-compat on resume: `revision_gate_choice`, `client_readiness_gate_choice`, `polish_gate_choice` — values still written (always `continue` / `apply`) so legacy validators don't fail, but no user gate produces them. Legacy values `accepted_early` / `skip_polish` / `skip` are accepted on read; the `skip_polish` value is normalised to `continue` on resume with a `legacy_value_migrated` event.

- **`continue/SKILL.md`** updated: the `revision_loop` and `client_readiness` resume branches mirror the auto-advance logic — no AskUserQuestion replay, no pre-polish gate replay.

### Tradeoffs accepted

1. Chat appears frozen for the full ~15–40 min post-source-review block (the TodoWrite panel is the only live signal).
2. No "accept v<N> early" — pipeline runs all iterations until mediator approves or `max_iterations` is reached.
3. No "export as-is" at forced exit — pipeline always runs client-readiness (with the banner).
4. No per-task "skip polish" — to disable polish, the user picks Quick mode upstream at Phase 1.5 (which sets `client_polish_enabled = false`).

If any of these become a problem in production, the gates can be re-added later as text-parsed end-of-turn checkpoints (the same pattern as v0.0.43 source-review). That alternative was scoped, drafted, and explicitly rejected during planning in favour of full autonomy.

### Files touched

- `skills/memo/SKILL.md` — Phase 5 heads-up extended; Phase 9 step 6 rewritten (auto-advance per verdict, no AskUserQuestion); Phase 10 pre-polish rewritten (auto-apply, no AskUserQuestion).
- `skills/continue/SKILL.md` — `revision_loop` and `client_readiness` resume branches simplified to mirror auto-advance.
- `skills/memo/references/events-contract.md` — added `gate_auto_advanced` event docs; updated `gate_answered` to drop `revision-iter` / `revision-forced-exit` / `polish` names; updated Phase 9/10 transition descriptions.
- `skills/memo/references/operating-contract.md` — AskUserQuestion usage table and "When to ask approval" list updated to remove Phase 9/10 entries.
- `skills/memo/references/pipeline-contract.md` — Phase 9/10 rows updated: Gates column now "none — auto-advance per verdict".
- `skills/memo/state-schema.md` — three gate-choice fields marked deprecated; new tasks write only `continue` / `apply`.
- `.claude-plugin/plugin.json`, `README.md`: version `0.0.44`.

### Verification

In a Cowork session: run `/memoforge:memo "<query>"`, approve the plan, let research run, type `continue` at the source-review checkpoint. The chat then goes quiet for ~15–30 minutes while the side panel cycles through items #10 → #11 (with iteration N updates) → #12 (with polish updates if applicable) → #13 → #14. At the end of Phase 12, the assistant turn ends, Cowork flushes the entire audit trail at once, and the final docx artifact card appears.

## 0.0.43 — 2026-05-21

Cowork dead-stuck fix: Phase 7.5 replaced with an explicit end-of-turn source-review checkpoint. Addresses the failure mode where v0.0.42 reached "Awaiting heartbeat confirmation" in the side panel but the chat remained frozen on the Phase 5 parallel-agent tile with the AskUserQuestion modal silently invisible.

### Root cause

Cowork's chat renderer only flushes assistant text on three triggers: end-of-assistant-turn, user input, or specific side-surface tool calls (TodoWrite → side panel). After a parallel Task batch, assistant text + AskUserQuestion modals + visualize widgets all buffer until one of those triggers fires. Documented Anthropic GitHub issues #26805, #29773, #29547, #33564, #44776 — all closed without upstream fix. The previous pipeline kept the assistant turn alive from Phase 5 dispatch through Phase 12 export (one giant turn), so chat never flushed mid-pipeline; AskUserQuestion at Phase 7.5 fired into a stuck-buffer state where the modal was in the DOM but not painted.

### Fix

- **Phase 7.5 rewritten.** No more AskUserQuestion. The new checkpoint: Read source-pack and currency-report (Cowork artifact cards), print a 📋 source digest + `continue`/`cancel` text instructions, then END THE ASSISTANT TURN EXPLICITLY. End-of-turn is Cowork's documented flush trigger; it paints all buffered Progress blocks from Phases 5/6/6.5/7 + the digest at once.
- **Phase 8 in-session resume parser.** Phase 8 now opens with a parse step that reads the user's reply at `current_phase == source_review_pending`. `continue` (or proceed/go/draft/yes/ok) → `current_phase = drafting`; `cancel` (or stop/abort/no) → `current_phase = cancelled_by_user`; anything else → re-show the checkpoint. Cross-session resume via `/memoforge:continue <task_id> [continue|cancel]` is handled by `continue/SKILL.md`.
- **New phase value `source_review_pending`** added to the canonical state.json enum, replacing the deprecated `heartbeat_pending`. Continue skill auto-migrates v0.0.42 tasks (drops `heartbeat_choice` field, emits `legacy_phase_migrated`).
- **Phase 5 heads-up strengthened.** New paragraph explicitly explains the silent inter-phase block and the source-review checkpoint as the flush point — pre-warns the user instead of leaving them confused.
- **TodoWrite item #9 renamed** "Heartbeat checkpoint" → "Source review" with activeForm `"Awaiting source review confirmation"`.

### Research-summary mode removed

The Phase 8 Branch A research-summary-only path was deleted as part of this simplification. The pipeline now always runs the full path (drafting + revision + client-readiness + export). The `templates/research-summary-only.md` file remains on disk as vestigial; legacy tasks resumed with `heartbeat_choice == "research_summary_only"` migrate silently to the full path (`legacy_mode_migrated` event). The v0.0.42 heartbeat AskUserQuestion's two options (Continue full / Research summary only) collapse into the single text-parsed `continue`/`cancel` gate.

### Files touched

- `skills/memo/SKILL.md` — Phase 5 heads-up extended; Phase 7 writes `source_review_pending`; Phase 7.5 fully rewritten (~90 → ~50 lines); Phase 8 simplified (Branch A removed, reply parser added).
- `skills/continue/SKILL.md` — resume table renamed `heartbeat_pending` → `source_review_pending` with legacy migration; drafting branch simplified.
- `skills/memo/references/progress-contract.md` — row 9.5 renamed; TodoWrite item #9 renamed.
- `skills/memo/references/pipeline-contract.md` — phase table updated; validators updated for legacy `heartbeat_choice`.
- `skills/memo/references/events-contract.md` — transition events updated for `source_review_pending`; gate-name `source-review` documented.
- `skills/memo/references/always-deliver.md` — heartbeat row replaced with source-review checkpoint table.
- `skills/memo/references/operating-contract.md` — AskUserQuestion usage table updated.
- `skills/memo/references/INDEX.md`, `progress-tracker.md` — minor cross-reference fixes.
- `skills/memo/state-schema.md` — `current_phase` enum updated; `heartbeat_choice` marked deprecated.
- `skills/status/SKILL.md` — resume hint for `source_review_pending` added.
- `templates/research-summary-only.md` — vestigial banner added at top of file.
- `.claude-plugin/plugin.json`, `README.md`: version `0.0.43`.

### Verification

In a Cowork session: run `/memoforge:memo "<query>"`, approve the plan, let research run. After Phase 7 source-pack completes, the assistant turn ends and Cowork flushes the entire Phase 5→7 audit trail at once, followed by the source digest and `continue`/`cancel` instructions. Type `continue` → drafting starts in a fresh turn with no chat-batching issue.

## 0.0.42 — 2026-05-21

UI sync fixes for Cowork — addresses five usability complaints from the v0.0.41 run: (1) parallel-research dispatch appearing as "1 agent" instead of N; (2) chat staying stuck on the first agent's notification while phases silently advance; (3) "unfreeze on user type" behaviour; (4) opaque progress between phase transitions; (5) empty right-side task panel.

### Side-panel channel (`TodoWrite`) becomes mandatory

- **`progress-contract.md` rewrite.** The previously-forbidding line "Updating internal TodoWrite items" is removed from "What does NOT count as a progress update". The `**Progress —**` chat block remains the PRIMARY signal; `TodoWrite` becomes a REQUIRED secondary channel that populates the right-side task panel.
- **Canonical 14-item TodoWrite list** added as a new contract section. Items #1–#14 mirror the existing 17-row chat-Progress checklist (with intake / mode / plan / approval / research / sufficiency / currency / source-pack / heartbeat / draft / revision / client-readiness / export / finalize compressed into one panel item each). Phase 5 adds N temporary sub-items (one per researcher in `dispatched_researchers`) so the user can see all N parallel agents simultaneously — Cowork's chat tile cluster may collapse them into a single visible tile, the side-panel sub-items are the reliable signal.
- **`memo/SKILL.md` updated** with `TodoWrite` calls at every phase transition (~16 sites: Phase 1 init, 1.5 mode, 3 plan, 4a/4b approval, 5 pre-dispatch and post-return, 6 sufficiency, 6.5 currency, 7 source-pack, 7.5 heartbeat and dismissal/unavailable fallbacks, 8 draft success and research-summary-only branch, 9 mediator-approved / accept-early / forced-exit-continue / forced-exit-skip / iteration-advance, 10 client-readiness, 11 export, 12 final). Each call is wrapped with "Silent skip if TodoWrite is unavailable" so hosts without the tool degrade gracefully.
- **`continue/SKILL.md` updated** with a `TodoWrite restoration on resume` table — on resume, the skill issues one TodoWrite with everything before the current phase = `completed`, current = `in_progress`, rest = `pending`. Phase 5 sub-items restored from `state.json.dispatched_researchers`. Without this, the right panel was blank after every resume.

### Chat dividers (`mark_chapter`)

- **`memo/SKILL.md` calls `mcp__ccd_session__mark_chapter`** at the 4 biggest phase boundaries: Phase 1 ("Intake & planning"), Phase 5 ("Parallel research"), Phase 7 ("Heartbeat checkpoint"), Phase 7.5/8 ("Drafting"), Phase 9 iteration N>1 ("Revision iteration <N>"), Phase 9→10 ("Client polish"), and Phase 10/11 ("Export"). Each is a TOC anchor visible in the Cowork side panel and a visible divider in chat. The tool call also helps break Cowork's text-batching between long autonomous blocks. Silent skip outside Cowork sessions.

### Phase 5 heads-up strengthened

- **The pre-dispatch heads-up message is rewritten** to explicitly state `**<N> parallel researcher agents**` (substituted with `len(dispatched_researchers)`) and warn about the Cowork UI quirk: "Cowork may show only 1 agent tile in the chat at first — the others will appear as they return." Pointer to the side panel for per-agent progress.
- **Post-return Progress block is now prescriptive**, not generic. The old "list research files and gaps" instruction routinely produced misleading sequential-sounding summaries ("Case law is in. Now the doctrinal layer.") even though all 3 researchers returned simultaneously. The new template forces "All <N> researchers returned in parallel — statutes.md (<lines>), case-law.md (<lines>), doctrine.md (<lines>). Gaps: <gaps>."

### Out of scope

- Sequential researcher dispatch (would trade parallel speedup for visibility) — user explicitly picked minimal scope.
- Top-level "pipeline appears stuck" banner — defers a proper heartbeat mechanism to avoid false positives on long-running agents.
- Cowork's underlying chat text-batching is a host-side limitation that the plugin can only mitigate via tool calls (`TodoWrite` / `mark_chapter`) — not directly fix.

### Verification

- `grep TodoWrite skills/memo/SKILL.md` — 16 mentions across phase transitions.
- `grep mark_chapter skills/memo/SKILL.md` — 5 mentions at phase-group boundaries.
- `progress-contract.md` no longer contains the forbidding line "Updating internal TodoWrite items"; the new "TodoWrite side-panel channel" section is present with the 14-item canonical list.
- `continue/SKILL.md` carries the resume-restoration table mapping each `current_phase` to its TodoWrite snapshot.

## 0.0.41 — 2026-05-21

`memo/SKILL.md` structural refactor. No behavioural changes — every runtime contract (validator schema, event taxonomy, fallback chain, sibling-skill cross-references) preserved verbatim. The goal was to relieve the orchestrator skill of accumulated reference material that had grown to 1388 lines.

### Refactor (memo/SKILL.md slimming — Medium scope: Tier 1 + Tier 2)

- **`memo/SKILL.md` reduced from 1388 to 1150 lines (−238, −17%).** Extraction follows the existing `references/` convention (canonical docs, demand-loaded per phase, INDEX.md navigation) — no new structural patterns introduced.
- **New `references/progress-contract.md`** (109 lines). Houses the previously-inline 100-line "User-visible progress contract" block: the canonical Cowork file-reference UX rule (D2 — single source of truth now), the v3 `Progress —` block format, the 16-row mandatory-update checklist (including Row 9.5 heartbeat and Row 16 final-export), and the "what does NOT count" list. Read once per activation, same convention as `operating-contract.md` and `events-contract.md`.
- **New `references/widget-schemas.md`** (123 lines). Consolidates the four `visualize:show_widget` data-payload schemas previously scattered through orchestration steps: §Elicitation (Phase 2a), §Mode mockup (Phase 1.5), §Plan diagram (Phase 4a), §Final dashboard (Phase 12). Each section includes the JSON shape, `show_widget` call arguments, and the `visualize_widget_rendered` event payload. SKILL.md phases now cite `§<name>` instead of inlining the JSON.
- **`operating-contract.md` gains a `## Hard constraints` section** with the 11 enforcement-level invariants previously living at the tail of SKILL.md (memo language English-only, `current_iteration` ownership, retry-budget persistence, validator gates, MCP fallback rules, default config, always-deliver invariant, etc.). SKILL.md's "Additional references" tail now points to that section.
- **`events-contract.md`-related dedup.** The 30-line inline Tier-1 events table (`phase_transition`, `agent_dispatched`, `agent_returned`, `gate_answered`, `validator_ran`) and the emission helper snippet in SKILL.md collapsed to a one-line citation of `events-contract.md §"When to emit — core five events (Tier 1)"` — the table itself was already canonical there.
- **File-reference rule (D2) deduplicated.** The canonical rule about Cowork rendering relative/absolute paths as non-clickable text and clickability coming from Write/Edit/Read artifact cards previously appeared verbatim in three places (Phase 1 work-dir explanation, Phase 2a intake, Phase 4a plan approval). Now lives in `progress-contract.md` only; the three other sites cite `§"How file references work in Cowork"`.
- **New `scripts/resolve_work_dir.sh`** (69 lines). Encapsulates Phase 1 task-id generation, output-folder resolution (4-candidate chain with mkdir/writable test), work directory tree creation (intake / checkpoints / research / research/raw / drafts / reviews / widgets / cache), and CWD-relative path computation via the `realpath → python3 → python → echo` fallback chain. Outputs `task_id=`, `work_dir=`, `rel_work_dir=`, `output_folder=` key=value lines for the orchestrator to parse. SKILL.md Phase 1 Task setup now calls the script with a single line; the 27-line inline bash block is gone.
- **`references/INDEX.md` updated.** Two new rows in the canonical-document map (progress-contract.md and widget-schemas.md). Conflict-resolution tier 4 lists the two new docs. The "When to read what (by orchestrator phase)" table grows three rows (pre-Phase-1 preamble reads progress-contract.md alongside operating-contract.md + events-contract.md; phases 2a / 4a / 12 demand-load widget-schemas.md).
- **Stale cross-references chased down.** Updated four legacy citations that pointed at the old inline section ("User-visible progress contract" in SKILL.md) to the new canonical document: `continue/SKILL.md` (×2 — resume Progress block format, post-phase Progress block), `progress-tracker.md` (Hard rules → checklist invariant), `always-deliver.md` Phase 11 fallback row, `modes.md` Phase 1.5 Progress template, plus the SKILL.md mode-pick Progress block back-reference.

### Out of scope (left for a future pass)

- **Agent-frontmatter delegation** of memo-writer / fact-assumption-analyst / revision-mediator inline guidance (~150 more lines extractable from SKILL.md, touches 3 agent files).
- **`scripts/merge_mode_config.py` and `scripts/export_docx.sh`** — judged not worth extracting in this pass: the mode-config block has interpolated placeholders (`researcher_set: [...]`) that would require introducing a config-matrix source-of-truth in the script (architectural shift outside Medium scope); the docx-export block is 8 lines of straight python invocation.
- **`state-schema.md` and `status/SKILL.md` local restatements** of the file-reference UX rule — acceptable local context (field-level schema comment, read-only sibling skill).

### Verification

- `python3 -m unittest scripts.tests.test_validate_state` — 35/35 tests pass; no behavioural regression.
- `bash scripts/resolve_work_dir.sh "<slug>"` end-to-end smoke test — produces the documented four-key output and creates the full work-dir subtree including `research/raw`.
- All §-anchors cited from SKILL.md resolve to existing headings in the target reference files (cross-checked: progress-contract.md §"How file references work in Cowork", §"Progress block format", §"Required progress updates — checklist"; widget-schemas.md §Elicitation / §Mode mockup / §Plan diagram / §Final dashboard; events-contract.md §"When to emit — core five events (Tier 1)"; operating-contract.md §"Hard constraints").
- All continue-skill back-references into memo SKILL.md (Phase 1.5, Phase 3, Phase 4a Path A step 1, Phase 7.5, Phase 8 branching, Row 9.5 of the checklist) resolve. Phase 4a Path A step 1's "Cowork strips `<details>` HTML" rationale is preserved verbatim — `continue/SKILL.md:148` cites it.
- Hard constraints transplanted verbatim (11 bullets — `intake/plan-review checkpoints`, `no worker subagents in reentry check`, `state outside work_dir`, `current_iteration ownership`, `validator gates`, `attempts persistence`, `no generic WebSearch fallback`, `MCP optional-only`, `default config / single iteration cap`, `English-only memo language`, `always-deliver invariant`).

## 0.0.40 — 2026-05-20

Fourth-wave contract-audit release (initial 11 fixes + 9 follow-up fixes for residual drift after the initial wave-4 push).

### Fixed (wave 4 follow-up — critical)

- **`mode_pick_pending` references in modes.md / progress-tracker (followup 1).** The wave-4 introduction of the dedicated `mode_pick_pending` phase between intake and planning left two stale references: `modes.md:26` still told the model "current_phase = planning is set before AskUserQuestion", and `progress-tracker.md:12` said Phase 2b sets `planning`. Both rewritten to match the actual contract (intake → `mode_pick_pending` → AskUserQuestion → `planning` atomic with mode write). A reader who skimmed only those files could re-introduce the bypass; now all three sources agree.
- **`state-schema.md` stale "heartbeat downgrade" + "researcher_set subset" notes (followup 2).** `config` comment still said "heartbeat may downgrade reviewer_list / max_iterations to Quick" (downgrade was removed in 0.0.39); `researcher_set` comment said "subset based on mode + plan.doctrine_required" (the candidate-vs-dispatched split landed in wave 4 Fix 6 — `researcher_set` is the candidate set, not mutated by `doctrine_required`; actual subset is in `dispatched_researchers`). Both rewritten to match contract.
- **Revision loop boundary fixed in `memo/SKILL.md:1067` (followup 3).** Gate 6b condition was `needs_revision AND current_iteration <= config.max_iterations`, which would offer "Continue iter N+1" on the last iteration (when iter N hit the cap). `continue/SKILL.md` and `revision-mediator.md` correctly use strict `<`. Memo/SKILL.md aligned to strict `<` and an inline explanation pinned the boundary; new `test_revision_loop_current_iteration_at_max_passes` test pins the contract (iter == max is valid; iter > max is the rejection boundary).
- **`/continue` `export` branch now mirrors the always-deliver fallback chain (followup 4).** Wave 4 Fix 2 rewrote `memo/SKILL.md` Phase 11 to copy markdown + update final_docx_path + push banner on python+pandoc failure, but `continue/SKILL.md:328` still described only the single python invocation + `current_phase = done`. A resume at `export` could leave the user without an artifact. Branch rewritten with all five steps (primary python → pandoc fallback → markdown delivery fallback → UX-visibility Read + markdown mirror → atomic state update).

### Fixed (wave 4 follow-up — substantive)

- **Currency JSON shape vs sufficiency reviewer reconciled (followup 5).** `currency-checker.md` JSON schema declares `warnings: <source_id>[]` (array of strings), but `research-sufficiency-reviewer.md` said to filter "warnings with `status == "manual_check"`" — a bare string has no `status` field. Reviewer rewritten: warnings is a string array; to learn per-source status, look up the same `source_id` in `sources[]` and read `sources[].status`. The data flow is unchanged; the documentation now reflects the actual shape.
- **WebSearch discovery boundaries unified across researchers (followup 6).** `currency-checker.md:126` said "do not discover new primary authorities and do not use generic WebSearch" — superficially contradicting line 14's "WebSearch is permitted as a discovery tool for currency signals". Reworded: WebSearch is allowed for currency signals on KNOWN source-pack items, never to surface new primary authorities. `case-law-researcher.md:104` said "do not use generic WebSearch for case law" — reworded to match the canonical §WebSearch policy (discovery permitted; citation forbidden; convert findings to MCP / WebFetch on issuing-body portal).
- **`fallback_summary_delivered` overload split (followup 7).** The status was used both for Phase 8 branch A (user-chosen research-summary mode via heartbeat) AND for the universal catastrophic fallback in `always-deliver.md`. `md_to_docx.py` unconditionally labelled it "RESEARCH SUMMARY MODE — IRAC ANALYSIS NOT PERFORMED", which is correct for the heartbeat path but a misleading label for an emergency fallback that happened to render docx. Phase 8 branch A now writes `fallback_research_summary_delivered`; universal fallback keeps `fallback_summary_delivered`. `md_to_docx.py` branches on the two statuses with distinct titles ("RESEARCH SUMMARY MODE" vs "PIPELINE FALLBACK — RESEARCH INCOMPLETE"). `state-schema.md` enum extended; `pipeline-contract.md` phase table updated; `continue/SKILL.md` normalizes legacy `fallback_summary_delivered` to `fallback_research_summary_delivered` on the research-summary resume path; banner test updated.
- **`legal-memo-style/SKILL.md` Fallback section aligned with Phase 11 (followup 8).** It still said "show markdown path, install python-docx" on pandoc failure — predating wave 4 Fix 2. Rewritten to reference the always-deliver.md markdown-delivery chain (cp → update final_docx_path → push banner → Read), matching `memo/SKILL.md` Phase 11.
- **`status` skill aware of markdown fallback artifact (followup 9).** `status/SKILL.md:81` printed `<max_iterations>` without the `config.` prefix (single-source-of-truth invariant from wave-3 0.0.39 says `config.max_iterations` is the only valid path); line 102 + line 109 always printed `memo-<slug>.docx`, which is wrong when Phase 11 delivered the markdown fallback. Lines updated to derive both the iteration cap and the final artifact basename from the actual state fields, so status output stays accurate across both export paths.

### Validator (wave 4 follow-up)

- New `test_revision_loop_current_iteration_at_max_passes` pins the revision-loop boundary: `current_iteration == config.max_iterations` is the LAST iteration and validation passes; `current_iteration > config.max_iterations` is the rejection boundary (already covered by `test_revision_loop_current_iteration_exceeds_max`). The strict `<` in gate 6b is now documented + boundary-tested.

### Wave 4 — original 11 fixes (preserved below)

Eleven discrepancies identified in the 2026-05-20 external audit, grouped into three severities.

### Fixed (wave 4 — critical, functional bugs)

- **/continue can no longer bypass Phase 1.5 mode choice (issue 1).** Intake parsers in `memo/SKILL.md` (Parsers 1, 2, 3 of Phase 2b) and `continue/SKILL.md` (Sub-path 1 `answer:` / `proceed`) used to set `current_phase = planning` directly after intake, with Phase 1.5 (mode choice) hidden inside the `planning` branch. A `/continue` resume from `intake_questions_pending` could therefore jump straight to Phase 3 with `state.json.mode = null`. A new dedicated phase `mode_pick_pending` now sits between `intake_questions_pending` and `planning` in `pipeline-contract.md`, `state-schema.md` enum, validator `PHASES_ORDERED`, and the continue-skill phase table. Intake parsers set `mode_pick_pending`; Phase 1.5 advances to `planning` atomically in the same write as the mode/config merge. /continue grows a dedicated `mode_pick_pending` branch that re-runs the AskUserQuestion, and the `planning` branch carries a defensive guard that bounces null-mode tasks back to `mode_pick_pending`.
- **docx export fallback now actually delivers the markdown artifact (issue 2).** `always-deliver.md` Phase 11 row promised that on python+pandoc double-failure the orchestrator would copy `drafts/v<N>-client-ready.md` to `<work_dir>/memo-<slug>.md` and update `final_docx_path` to the .md path. `memo/SKILL.md:1151-1155` instead told the user "docx export failed — install python-docx manually" and left `final_docx_path = null` — violating the always-deliver invariant. Phase 11 fallback step now exactly matches `always-deliver.md`: copy → update `final_docx_path` (extension `.md`) → push fallback banner → `Read` for artifact card → `current_phase = done`. Users never reach `done` without a file.
- **Validator now enforces canonical researcher_set, template_constraint, selected_template ∈ allowed_set, and final_docx_path existence on disk (issue 10).** `validate_state.py:MODE_CANONICAL_CONFIG` only checked 4 of the per-mode canonical config values. The previous `test_revision_loop_standard_mode_passes` froze `allowed_set: ["classical-memo"]` as a Standard config — an invalid value per `modes.md` which the validator was happy to accept. New `MODE_RESEARCHER_SET` and `MODE_TEMPLATE_CONSTRAINT` mappings drive cross-field validation. `done` phase now requires `Path(final_docx_path).is_file()` AND an absolute path. Eight new tests cover the gaps; the bug-frozen test is fixed to use the canonical 3-template `allowed_set`.

### Fixed (wave 4 — high, contract drift)

- **`currency-report.json` is now canonical in Phase 6.5 outputs (issue 4).** `pipeline-contract.md` phase table only listed `research/currency-report.md`, but `currency-checker.md` writes both files and Phase 7 expects the .json. Contract row updated; `memo/SKILL.md:868` now explicitly mentions both files; progress block reads counts from .json (`len(blocking)` / `len(warnings)`) instead of parsing emoji from .md.
- **Sufficiency is re-gated after currency invalidates sources (issue 5).** Pipeline order is `research → sufficiency → currency → source pack` (per the CHANGELOG 0.0.39 wave 2 entry), but sufficiency-reviewer was claimed to be "currency-aware" while running BEFORE currency. If currency-checker marked a relied-upon source as `do_not_use`, the sufficiency verdict was stale and no re-gate fired. `memo/SKILL.md` Phase 6.5 and `continue/SKILL.md` `currency_check` branch now check `currency-report.json.blocking` after currency-checker returns: if non-empty AND `state.json.attempts.sufficiency_regate == 0`, atomically re-dispatch `research-sufficiency-reviewer` once (bounded by `attempts.sufficiency_regate` max 1, enforced by validator). `research-sufficiency-reviewer.md` reworded to drop the "may run before or after" hedge and to MUST-treat `blocking` source_ids as removed from the pool on the re-gate pass.
- **`dispatched_researchers` separates candidate set from actual dispatch (issue 6).** `state.json.config.researcher_set` is the CANDIDATE set per modes.md (Quick = `["statutory"]`, Standard/Deep = `["statutory","case-law","doctrinal"]` regardless of `Doctrine` flag). New `state.json.dispatched_researchers` records the filtered subset memo Phase 5 actually invoked (doctrinal omitted when plan says `Doctrine: no`). The `phase5_dispatch` event now carries `{candidate, dispatched, skipped, skip_reasons}`. The "malformed dispatch" audit check is now `agent_call_count == len(dispatched_researchers)`, so a legitimate `Doctrine: no` skip is no longer flagged. Validator enforces `dispatched_researchers ⊆ config.researcher_set` from phase `research_sufficiency` onward.
- **Plan approval gate no longer references `<details>` (issue 7).** `memo/SKILL.md:728` falsely claimed "the `<details>` markdown block above already gives the user the full plan text" — but Phase 4a Path A removed the `<details>` block specifically because Cowork strips the tags. Same false reference lived in `operating-contract.md:67`. Both reworded: the bullet preview + `plan.md` artifact card are the in-chat affordances; `<details>` collapsibles are explicitly banned.
- **`final_docx_path` semantics unified to absolute (issue 8).** `state-schema.md:103` said "absolute path", `memo/SKILL.md:1157` said "relative to CWD", `memo/SKILL.md:1194` used the legacy `<final_artifacts_dir>` field that line 1157 itself called removed. All three now agree: absolute path equal to `<work_dir>/memo-<slug>.{docx|md}`, validator enforces `is_file()`, Phase 12 dashboard uses `<state.json.work_dir>` instead of `<final_artifacts_dir>`.

### Fixed (wave 4 — medium, doc/clarity drift)

- **WebSearch policy explicitly covers `fact-assumption-analyst` (issue 3).** `pipeline-contract.md` §WebSearch listed four researchers as WebSearch-permitted but didn't mention that `fact-assumption-analyst` inherits the full tool surface (per the Tool inheritance table below it). Added a paragraph clarifying that the analyst's WebSearch use is constrained to preliminary triage and never cited as a legal source — the §WebSearch whitelist is about CITATION authority, not USE.
- **House style mode-dependent exit thresholds (issue 9).** `legal-memo-house-style.md:107-110` hard-coded `max_iterations: 3` + "all five reviewers", contradicting Quick mode (1 iteration, 3 reviewers). Section rewritten with explicit per-mode rows pointing to `modes.md`.
- **`disable-model-invocation: true` added to entry-skill frontmatters (issue 11).** `README.md:97` advertised this field for `memo`, `continue`, `status` but none of their frontmatters carried it. Added to all three. Hosts that don't recognize the field ignore it; hosts that do (Cowork) treat `/memoforge:*` slashes as the only invocation path.

### Validator

- `PHASES_ORDERED` extended with `mode_pick_pending`.
- `MODE_RESEARCHER_SET`, `MODE_TEMPLATE_CONSTRAINT` introduced; per-mode `researcher_set`, `template_constraint.{mode, template_id, allowed_set}`, and `classification.selected_template_id ∈ template_constraint.allowed_set` are now cross-checked.
- `dispatched_researchers` (subset of `config.researcher_set`) required from `research_sufficiency` onward.
- `attempts.sufficiency_regate` bounded to 0 or 1.
- `final_docx_path` in `done` must be absolute and `is_file()`.
- 8 new tests cover the new rules; the previously bug-frozen `standard_mode_config()` helper now uses the canonical 3-template `allowed_set`.

## 0.0.39 — 2026-05-20

Contract-audit release. Three waves of fixes:
- **Wave 1** (initial 0.0.39 push): the 10 blocking + 12 moderate discrepancies in agents and validators identified by the v0.0.38 audit.
- **Wave 2** (follow-up to wave 1): the 5 critical + 5 moderate residual discrepancies in `memo/SKILL.md`, `continue/SKILL.md`, contract docs, README, and templates that wave 1 did not touch.
- **Wave 3** (follow-up to wave 2): 5 critical + 6 substantive issues uncovered by the third audit pass — Phase 1 ordering, terminal-state validation, mode↔config integrity, currency JSON wiring through orchestration, fallback banner pushes, event-name unification, allowed-tools cap, reviewer length-overflow guard, and docx banner title for approved+fallback.

### Fixed (wave 3 — critical)

- **Phase 1 ordering reversed (issue 1).** `skills/memo/SKILL.md` Phase 1 now runs in the correct order: (1) Task setup (creates work_dir, `state.json` with `config: {}`, `events.jsonl`), then (2) MCP precheck, then (3) Visualize precheck, then (4) Dispatch `fact-assumption-analyst`. Previously the prechecks ran first and tried to write `mcp_precheck_result` / `visualize_precheck_result` events to a non-existent `events.jsonl` and set `state.json.config.visualize_*` keys before the file existed. Detection results that should have surfaced in `events.jsonl` and survived into Phase 1.5 merging were lost.
- **`continue` skill no longer hangs on hosts without AskUserQuestion-friendly intake (issue 2).** Sub-path 2 (resume at `intake_questions_pending` with valid JSON) used to walk `must_answer` through AskUserQuestion, but memo skill Phase 2a moved off that pattern in production (silent-fail bug). Sub-path 2 is now split into Sub-path 2a (visualize elicitation, when `visualize_enabled=true`) and Sub-path 2b (text fallback, otherwise) — exactly mirroring memo Phase 2a Path A / Path B.
- **`switch_to_quick` cleanup completed (issue 3).** Wave 2 missed `always-deliver.md` Phase 7→8 row and `operating-contract.md` §"When to ask approval" — both still listed "Switch to Quick mode now" as a heartbeat option. Updated to two options (`continue_full`, `research_summary_only`) with a pointer to `modes.md` §"Mid-run mode escalation" explaining why downgrade was removed.
- **Terminal phases bypass phase-aware checks (issue 4).** `validate_state.py:PHASES_ORDERED` placed `failed` and `cancelled_by_user` AFTER `done`, so `phase_at_or_after("cancelled_by_user", "planning")` returned True — requiring mode/config/current_draft_path/final_status/sufficiency.json for a task cancelled at intake. Validator now early-returns after always-required checks when `current_phase ∈ {failed, cancelled_by_user}`. Two new tests cover this.
- **`validate_state.py` enforces mode↔config canonical values (issue 5).** Previously Quick mode with `max_iterations=99, client_polish_enabled=true, max_client_polish=2, targeted_followup_forced=true` passed validation (only reviewer_list was checked). Validator now also enforces the canonical config matrix from `modes.md`: `quick → (1/false/0/false)`, `standard → (3/true/1/false)`, `deep → (3/true/2/true)`. Misconfigured tasks fail validation immediately. Three new tests cover this.

### Fixed (wave 3 — substantive)

- **Currency JSON now passed through orchestration (issue 6).** Wave 1 introduced `research/currency-report.json` and wired downstream agents to consume it, but memo skill Phase 7/8/9/10 dispatches only passed `research/currency-report.md`. Now Phase 7 `source-pack-builder` dispatch, Phase 8 `memo-writer` dispatch, Phase 9 `citation-auditor` example, and Phase 10 `client-readiness-reviewer` dispatch all pass both files (markdown view + canonical JSON view).
- **MCP unavailable now pushes fallback banner (issue 7).** Phase 1 precheck used to print a heads-up to chat but did not push to `state.json.fallback_banners[]`, so the documented banners from `always-deliver.md` Phase 5 row never surfaced in the docx. Phase 1 now pushes `"MCP servers unavailable…"` (both missing) or `"Partial MCP coverage…"` (one missing) and logs `fallback_invoked` with `fallback_name: mcp_unavailable` or `mcp_partial`.
- **Event name `mcp_ratelimit_fallback` is now canonical everywhere (issue 8).** `pipeline-contract.md` §WebSearch said to log `mcp_rate_limited`, but agents emit `mcp_ratelimit_fallback`, `memo/SKILL.md` Phase 5 greps for `mcp_ratelimit_fallback`, and `always-deliver.md` uses `mcp_ratelimit_fallback`. The single divergent reference in `pipeline-contract.md` is now corrected. Reality wins.
- **`Glob, Grep` added to `allowed-tools` cap for both skills (issue 9).** `memo/SKILL.md` and `continue/SKILL.md` frontmatter now explicitly list `Glob, Grep`. citation-auditor declares `Read, Write, Glob`; source-pack-builder and research-sufficiency-reviewer declare `Read, Write, Glob, Grep` in their own frontmatter. Defensive — if the host treats the parent skill's `allowed-tools` as a hard cap on subagent inheritance, raw-layer audit no longer breaks.
- **Reviewers now block on `length_overflow_recommendation: true` (issue 10).** `memo-writer.md` had promised that logic-reviewer and citation-auditor would block on this YAML front-matter flag (set when a forced template like executive-brief cannot defensibly cover the issues), but neither reviewer's prompt mentioned it. Now logic-reviewer "What you check" includes a `Length overflow disclosure` rule, and citation-auditor adds a sixth-priority `length_overflow_disclosure` issue category (also added to `validate_review_json.py:CITATIONS_ISSUE_CATEGORIES`). Both reviewers emit a blocking issue when the flag is present, surfacing the writer's self-disclosure to the mediator and ultimately to the user.
- **Banner title fixed for approved+fallback (issue 11).** `md_to_docx.py` showed a banner whenever `final_status` was not `approved` OR `fallback_banners` was non-empty (so a memo approved by reviewers but with an MCP rate-limit fallback got a banner). But the default title was "MANUAL REVIEW REQUIRED" — too alarming for a successfully approved memo. New branch: when `final_status` starts with `approved` AND `fallback_banners` is non-empty, title becomes "PIPELINE FALLBACK NOTICE — REVIEW BEFORE CLIENT USE" and the subtitle accurately states the reviewer loop approved the content while disclosing the research-time fallbacks.



### Fixed (wave 2 — orchestration, contract docs, templates)

- **`switch_to_quick` removed everywhere consistently.** Wave 1 removed the value from `validate_state.py`, but left it live in `skills/memo/SKILL.md` (UI option + heartbeat write branch), `skills/memo/state-schema.md`, `skills/memo/references/pipeline-contract.md`, `skills/memo/references/modes.md` (mid-run downgrade section), and `skills/continue/SKILL.md`. Heartbeat AskUserQuestion now exactly two options (`Continue full loop`, `Research summary only`). State schema, pipeline contract, and continue skill normalize legacy `"switch_to_quick"` values written by pre-0.0.39 tasks to `"continue_full"` on resume. `modes.md` documents that mid-run downgrade is not supported until reimplemented.
- **Phase 2a non-visual intake hang fixed.** Wave 1's audit identified that `skills/memo/SKILL.md:382` said "visualize disabled → Path B" but `:465` made Path B fire only if `visualize_enabled == false` AND `intake-questions.json` is missing/invalid — leaving non-visualize hosts with valid JSON in a dead branch. Path B condition rewritten as an OR (either condition triggers Path B), so non-visualize Claude Code installs no longer stall after intake.
- **`continue` skill allowed-tools aligned with `memo`.** Wave 1 missed that `skills/continue/SKILL.md:5` had only `Read, Write, Edit, Bash, Task, AskUserQuestion` — no `WebFetch`, `WebSearch`, or MCP. Since researchers without `tools:` inherit from the parent skill, resumed `research` / `currency_check` / `research_sufficiency` follow-up dispatches via `/continue` were silently losing MCP and discovery tools. The continue skill now mirrors the memo skill's full `allowed-tools` list including the `mcp__*` wildcard.
- **`mcp__*` wildcard added to memo + continue allowed-tools.** The plugin-scoped MCP prefix `mcp__plugin_memoforge_*` declared in the frontmatter does not match the opaque UUID namespace Cowork actually uses (documented at `memo/SKILL.md:186`). The wildcard ensures MCP tools are inherited regardless of the host's namespace convention. Pipeline-contract.md §Tool inheritance updated to reflect this.
- **Deep mode `targeted_followup_forced` now actually forces a follow-up.** `modes.md:79` declares that Deep mode forces one targeted follow-up even when the sufficiency verdict is `sufficient`, but `memo/SKILL.md:839` and `continue/SKILL.md` only handled `targeted_followup_needed`. Both now branch on `state.json.config.targeted_followup_forced` and, when true, synthesize a follow-up prompt for the weakest issue (per `sufficiency.issue_coverage[]`) and fall through to the standard targeted-followup branch.

### Fixed (wave 2 — currency JSON wiring, template auto-detection, raw paths)

- **`source-pack-builder`, `citation-auditor`, and `memo-writer` now consume `research/currency-report.json`** (introduced in wave 1) instead of parsing markdown emoji. The markdown view remains for human review. Canonical emoji→status mapping documented in `agents/currency-checker.md` is the fallback when only the markdown exists (legacy tasks).
- **`style-reviewer` template auto-detection extended for `regulatory-analysis`.** Wave 1 only added auto-detection for `research-summary-only` and `cross-jurisdictional`. But the regulatory-analysis template uses `Compliance: <verdict>.` lines in section 8 (Obligations breakdown) — not `Risk: <verdict>.` — so wave 1's Risk-pattern check still flagged every obligation subsection as a structural defect. Style-reviewer now detects regulatory-analysis by header regulation identifier OR section heading `## <N>. Obligations breakdown` OR presence of `Compliance: ...` lines, and accepts `Compliance: <verdict>.` (and the section-7 `Applies: <verdict>.` scope-test variant) in place of `Risk: <verdict>.`
- **`cross-jurisdictional` template now requires the canonical `Risk: <highest_verdict>.` summary line.** Wave 1 updated memo-writer and style-reviewer to expect this line, but did not update the template itself. The template now mandates it after the per-jurisdiction lines.
- **`research-sufficiency-reviewer` raw-layer existence check updated to layered structure.** Wave 1 moved raw files from `research/raw/<slug>.md` to `research/raw/<layer>/<slug>.md` but research-sufficiency-reviewer was still looking at the flat path. Now it uses `research/raw/<layer>/_index.json` to resolve citations to canonical slugs and globs `research/raw/**/*.md` for existence.
- **`continue` skill no longer demands inlined plan.md in `<details>`.** `memo/SKILL.md:652` explicitly forbids this (Cowork strips `<details>` HTML inconsistently); the continue skill replays the same 5-8 bullet preview format used by the memo skill Phase 4a Path A.

### Fixed (wave 2 — release hygiene / docs)

- **`README.md` pipeline order corrected.** Was `research → sufficiency → source pack → currency check`; actual contract is `research → sufficiency → currency check → source pack`. Reviewer counts also clarified per mode (3 in Quick, 5 in Standard/Deep).
- **`README.md` work-directory path corrected.** No longer claims artifacts live under `${CLAUDE_PLUGIN_DATA}/work/<task_id>/` (this hasn't been true since 0.0.29); now describes the resolved output-folder path with the actual resolution order.
- **`pipeline-contract.md` revision header bumped from "0.0.38" to "0.0.39"** and Tool inheritance section updated to reflect `mcp__*` wildcard, removed `fact-assumption-analyst` explicit allowlist, and `citation-auditor` Glob.

### Wave 1 — original 0.0.39 fixes (preserved below)

Contract-audit release. Resolves all 10 blocking and 12 moderate discrepancies identified in the v0.0.38 audit between reviewer agents, validators, and the rest of the pipeline.

### Fixed (blocking — corrects silent quality degradation)

- **`counterargument-reviewer` can now actually find missing contrary authority.** Added `research/statutes.md`, `research/case-law.md`, `research/doctrine.md` to `Inputs`. Previously the reviewer only saw the curated `source-pack.md` (where dropped sources are absent), making the `contrary_authority` attack vector unusable. The agent is now instructed to check each researcher's `## Considered but excluded` section before claiming an authority is missing.
- **`research-sufficiency-reviewer` now sees `currency-report.md`.** Sufficiency verdict now accounts for repealed/overruled sources; a research file relying on a ❌-marked source is automatically `targeted_followup_needed` or stronger.
- **`citation-auditor` can now enumerate `research/raw/`.** Added `Glob` to its tools; the verbatim-quote verification check (`unverified_against_source`) actually works now. Also fixed "five checks" → "six checks" in the prompt (the sixth check was added without renumbering).
- **`research/raw/` race + slug collisions resolved.** Researchers now write to layer-prefixed sub-directories: `research/raw/case-law/<slug>.md`, `research/raw/statutes/<slug>.md`, `research/raw/doctrine/<slug>.md`. Each layer maintains an `_index.json` slug registry with `{slug, source_title, citation_form, url, retrieved_at}` so `citation-auditor` can resolve any citation to a raw file without guessing the slug. Two researchers can no longer overwrite each other's `gdpr-art-6.md`.
- **`memo-writer` em-dash rule unified with house-style.** The old absolute "No em dashes" rule contradicted the house-style allowance of `Term — definition.` in the Background section. Memo-writer now says exactly what house-style says: no em dashes in body text; the definition format is the only allowed em-dash usage.
- **`cross-jurisdictional` template no longer fights `style-reviewer`.** Memo-writer now adds a canonical `Risk: <highest_verdict>.` summary line after per-jurisdiction lines, and style-reviewer's Risk-pattern check now accepts both forms.
- **`research-summary-only` template no longer triggers infinite style-reviewer flags.** Style-reviewer now auto-detects the template from the draft's title (`(no legal conclusions)`) or header status line (`Status: research findings only…`) and skips the 4-beat Risk pattern check for that template. Definitions, title format, tone, and grammar checks still apply.
- **`fact-assumption-analyst` no longer relies on a hardcoded MCP namespace.** Frontmatter `tools:` line is removed entirely, so the agent inherits all MCP tools from the main session like every other researcher (detects MCP servers by function name at runtime). The previous hardcoded `mcp__plugin_memoforge_*` prefix was fragile in environments that surface MCP under UUID namespaces.
- **`switch_to_quick` heartbeat enum removed.** The value was declared but had no Phase 8 branching logic; users selecting it got `continue_full` behaviour silently. Validator `VALID_HEARTBEAT_CHOICES` now lists only `{pending, continue_full, research_summary_only}`. (Mode-downgrade after Phase 7.5 will be a separate feature if requested.)
- **Reviewer JSON heterogeneity preserved through the mediator.** Mediator now emits category labels in the consolidated output: `[from citations | unsupported_claim]`, `[from counterarguments | contrary_authority]`, etc. Writer now sees the *type* of fix (paraphrase vs unsupported vs currency) rather than a generic issue+suggestion.

### Fixed (moderate)

- **`currency-checker` emits parallel JSON output.** New `research/currency-report.json` with explicit enum statuses (`current | outdated_but_usable | do_not_use | manual_check`) and emoji→status mapping documented. Downstream agents (`source-pack-builder`, `citation-auditor`, `memo-writer`) no longer have to parse markdown emoji.
- **`validate_state.py` enforces mode ↔ reviewer_list mapping.**
  - `mode=quick` ⇒ `reviewer_list` must equal `{logic, citations, counterarguments}`.
  - `mode in {standard, deep}` ⇒ `reviewer_list` must include all 5.
  Previously a Quick task with all 5 reviewers passed validation and led to silently-overspent reviewer runs.
- **`validate_state.py` checks for `research/research-sufficiency.json` existence from `source_pack` phase onward.** Catches malformed runs where the sufficiency gate was silently skipped.
- **`validate_review_json.py` enforces per-reviewer category enums.** `citations` reviewer must classify each blocking issue with `issue_category` from the 6-value enum; `counterarguments` reviewer must classify with `attack_vector` from the 5-value enum (post-removal of `client_readiness`). Length warnings (not errors) emitted when an `issue` exceeds 1500 chars or a `suggestion` exceeds 800 chars to flag runaway reviewer output before it floods writer context.
- **`counterargument-reviewer` `attack_vector` enum trimmed from 6 to 5.** Removed `client_readiness` (duplicated Phase 10 `client-readiness-reviewer` role). The failure-stub generator in `validate_review_json.py` now defaults to `understated_risk` instead.
- **`client-readiness-reviewer` JSON schema gained `version_reviewed`.** Now consistent with the 5 revision-loop reviewers.
- **`revision-mediator` cross-version sanity check.** Mediator now verifies every reviewer JSON has the same `version_reviewed` matching `state.json.current_iteration` before consolidating. Detects orchestration races where a stale reviewer file leaks into a new iteration.
- **`revision-mediator` Inputs documentation now mode-conditional.** Quick mode mediators no longer read instructions claiming clarity/style file paths are passed.
- **`memo-writer` Template-specific deviations cover `research-summary-only`.** Previously the writer would receive `template_id = research-summary-only` while the prompt still required the 4-beat pattern; now the exception is documented in three places (overview, Rules, deviations).
- **`memo-writer` dead verbatim-request path removed.** Replaced "request verbatim in your final response" (which nothing listened to) with a narrow exception allowing direct `Read` of `research/raw/<layer>/<slug>.md` when the analyzed layer truncated a quote needed for the Risk subsection.

### Internal

- `validate_payload()` in `validate_review_json.py` now returns `(errors, warnings)` tuple instead of `errors`; warnings surface in the validator output without failing validation.
- Existing tests in `scripts/tests/` may need updates for the heartbeat-enum and mode↔reviewer_list cross-validation changes; rerun `python3 -m unittest discover scripts/tests -v` and adjust failing tests if any.

## 0.0.38 — 2026-05-20

Contract-sync release. All 12 verified discrepancies between docs, validators, scripts, and agent prompts were resolved. The pipeline now has a single source of truth for every contract — `skills/memo/references/pipeline-contract.md`.

### Fixed (runtime correctness)

- **Tool inheritance.** `skills/memo/SKILL.md:5` `allowed-tools` now includes `WebFetch`, `WebSearch`, and the two MCP namespace prefixes (`mcp__plugin_memoforge_courtlistener__*`, `mcp__plugin_memoforge_legal-data-hunter__*`). Researcher subagents that omit `tools:` now actually inherit the MCP / WebFetch / WebSearch surface they were always written to use.
- **`fact-assumption-analyst` MCP access.** Frontmatter `tools:` now lists both MCP namespaces in addition to `Read, Write, Glob, Grep, WebFetch`, matching the body instructions.
- **Quick mode end-to-end.**
  - `skills/memo/SKILL.md:920` (Phase 9) and `skills/continue/SKILL.md` (revision_loop branch) now read `state.json.config.reviewer_list` and dispatch only the configured reviewers (3 in Quick, 5 in Standard/Deep).
  - `scripts/validate_review_json.py` is mode-aware: accepts a `--reviewers <comma_list>` CLI flag and otherwise reads `state.json.config.reviewer_list`. Defaults to all five only when neither is present.
  - `agents/revision-mediator.md` consumes only reviewers in `state.json.config.reviewer_list`, approves with `K` (not 5) green reviewers, and includes only those reviewers in the `iterations[]` entry.
  - `skills/revision-loop/SKILL.md` description and exit conditions are mode-aware.
- **Singular → plural rename for the counterargument reviewer kind.** `modes.md` and `state-schema.md` now use `counterarguments` (plural), matching the validator, mediator, file names, and reviewer JSON output. The validator rejects `counterargument` (singular).
- **`research_summary_only` branch wired end-to-end.**
  - New template `templates/research-summary-only.md` (no IRAC, no Risk subsections, no Recommendation — descriptive only, with explicit "open questions" lists).
  - `skills/memo/SKILL.md` Phase 8 Branch A: when `heartbeat_choice == "research_summary_only"`, overrides `selected_template_id`, injects the documented banner into `fallback_banners[]`, sets `final_status = "fallback_summary_delivered"` and `current_phase = export`, skipping Phase 9 + Phase 10.
  - `skills/continue/SKILL.md` `drafting` branch mirrors the same logic for resume paths.
- **Visualize state placement.** Phase 1 initial state now creates `state.json.config = {}` so the visualize precheck can populate `visualize_enabled` / `visualize_namespace` without KeyError. Phase 1.5 now MERGES mode config into existing `state.json.config` (read-modify-write via Python) instead of overwriting, preserving the visualize fields. `state-schema.md` lists `visualize_enabled` and `visualize_namespace` as canonical config keys.
- **`max_iterations` single source of truth.** Removed top-level `max_iterations` from `state-schema.md`, Phase 1 init template, and SKILL.md narrative. The only authoritative value is `state.json.config.max_iterations` (Quick=1, Standard=3, Deep=3). `revision-mediator.md` and `continue/SKILL.md` now read the nested field explicitly. `validate_state.py` rejects state files that include the top-level field.

### Fixed (validators)

- **`scripts/validate_state.py`** is phase-aware. Always-required fields now include `work_dir`, `rel_work_dir`, `output_folder`, `mode`, `config`, `heartbeat_choice`, gate choices, `fallback_banners`, `events_path`. From `planning` phase onward, `mode` must be set and `config` must contain the seven mode-config keys. From `drafting` onward, `current_draft_path` must be set. From `revision_loop` onward, `current_iteration` must be ≥ 1 and ≤ `config.max_iterations`. From `export` onward, `final_status` must be set. The validator also rejects unknown reviewer kinds and the deprecated top-level `max_iterations`.
- **New `scripts/tests/` directory** with `unittest` smoke tests covering Quick / Standard mode dispatch, `research_summary_only` heartbeat acceptance, top-level `max_iterations` rejection, singular `counterargument` rejection, mode-aware reviewer validation, and `fallback_banners[]` rendering in the docx warning banner. 21 tests in total; run via `python3 -m unittest discover scripts/tests -v`.

### Fixed (docs / policy unification)

- **WebSearch policy** consolidated into one canonical paragraph in `skills/memo/references/pipeline-contract.md §WebSearch` and the README. SKILL.md, continue/SKILL.md, and the four discovery-capable researcher prompts (`statutory-researcher`, `case-law-researcher`, `currency-checker`, `doctrinal-researcher`) now cite the canonical policy at the top of their boundaries section and only retain operational specifics. Two distinct MCP-failure fallback paths (*unavailable* vs *rate-limited / 5xx*) are now documented.
- **File-link UX** rule resolved per **D2 (plain text + artifact cards)**. Path A elicitation and plan-approval flows in `skills/memo/SKILL.md` no longer require markdown links on file paths. The empirical `:86-91` stance (Cowork does not render relative or absolute paths as clickable inside chat text — clickability comes from artifact cards) is now the single rule; all other sites updated to match.
- **Export paths.** `skills/continue/SKILL.md` export branch now says "writes directly into work_dir" (no copy step), matching `skills/memo/SKILL.md` Phase 11. `skills/legal-memo-style/SKILL.md` now uses `$WORK_DIR/memo-<slug>.docx` (previously the obsolete `${CLAUDE_PLUGIN_DATA}/work/<task_id>/final/` path).
- **`fallback_banners[]` rendered in docx.** `scripts/md_to_docx.py:add_warning_banner` now reads `state.json.fallback_banners[]` via the new `extract_fallback_banners()` function and renders each entry as a bullet in a "Pipeline fallbacks that fired during this run" sub-section of the warning banner. The banner now fires even when `final_status` starts with `approved`, as long as fallback_banners is non-empty (covers MCP-rate-limited + success and similar cases). `fallback_summary_delivered` final_status gets a custom title `RESEARCH SUMMARY MODE — IRAC ANALYSIS NOT PERFORMED`.
- **Widget paths.** 11 hardcoded `work/<task_id>/widgets/` references in `skills/memo/SKILL.md` are now `$WORK_DIR/widgets/`, honoring the resolved working directory. Two `work/<task_id>/cache/` references also migrated.
- **New `skills/memo/references/pipeline-contract.md`** is the canonical phase table + state schema + tool inheritance + validator contract + file-link UX + WebSearch policy + release hygiene. All other docs now cite this file instead of restating.

### Release hygiene

- New `CHANGELOG.md` at the repo root (this file).
- `README.md` version bumped from the stale `0.0.2` to `0.0.38`.
- `.claude-plugin/plugin.json` version bumped from `0.0.37` to `0.0.38`.
- Future releases follow the atomic procedure in `pipeline-contract.md §Release hygiene`.

## 0.0.37 and earlier

No formal changelog was maintained for prior releases. `dist/memoforge-<version>.zip` archives capture the binary state for versions 0.0.17 through 0.0.37. Reconstruct from `git log` if needed.
