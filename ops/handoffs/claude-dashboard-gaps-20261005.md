# Dashboard gaps — implementation (CLAUDE-DASHBOARD-GAPS-20261005)

Claude worker under claude:1863d2b5 · 2026-10-05 · branch `claude/dashboard-gaps-20261005`
off origin/main `dd0dd740`, own worktree. Not pushed (no push rights); SHAs below are for
ops-dashboard to integrate. No shared-tree or review-branch edits, no main merge, live
8098/8099 servers untouched (one read-only `GET /api/state`; test servers ran on 8197).

## Audit: what already worked (origin/main dd0dd740, live state 2026-10-05 01:20Z)

Source `[SRC]` and one read-only `/api/state` `[API]` (4.3 MB, 12 agents, 333 runs). No browser pass.

| Area | Already present | Gap |
|---|---|---|
| Release readiness | `release-readiness.js` derives per-game status + six gates (gameplay, input, correctness, performance, distribution, package), blockers, production membership from a hash-verified snapshot. Corpus has release filter chips and per-candidate gate detail. `[SRC]` | No single "what is left per unreleased game" list; gates visible only one candidate at a time. Stale reviews said only `reviewStale: true`, not why. `[API]` 103 unreleased games, 62 with reviewed gameplay, 0 ready, 4 recorded reviews all stale (source hashes no longer match). |
| FPS labels | `corpusFps` keeps metric-specific labels (logical gameplay frames/s, guest Flip events/s, guest presentation events/s); readers reject unqualified counters. `[SRC]` | Not shown next to release gates. `[API]` 4 unreleased games have a reviewed logical-frame rate; 1 has only an unreviewed historical Flip-event rate. |
| Sound evidence | none | No gate and no `result.json` field records audio (census of 341 result.json files: no audio key). Shown as "not recorded". |
| Launch | `emulator-server.js` catalog: per-app route, availability, `missingPaths`; corpus card + detail show Launch / Launch unavailable with reason and missing files (detail only). `[SRC]` | No build identity at launch; served files are the live root tree. |
| Commit visibility | Activity shows commits (subject, author, hash, GitHub link) `[SRC activity.js]` | No main/branch/pushed/deployed state. |
| Agents | Overview + Agents cards, `agentSignal` attention ranking; subagent rows exist only on `origin/ops/subagent-summaries-20261004` (63a248a6), not on main. `[SRC]` | Two-column grid (`style.css .agent-list`), multi-row cards. |
| Blockers | Shared `blocker-model.js` kinds (Dependency / Review blocked / Capacity needed / Needs follow-up), Telegram `/blockers` uses it. `[SRC]` | No "needs user input" vs "agent-resolvable" split. |
| Perf comparison | Per-run perf samples only. | No before/after comparison. |

## Commits

### 1. Ready for desktop view (DASH-GAPS-READY-DESKTOP)

- New nav view **Ready for desktop** (`#release`): one row per unreleased game (verified
  membership `no`); reviewed gameplay screenshot (opens the run), recorded rate with its metric
  label + reviewed/unreviewed + qualification state, or **Rate unknown — no measurement
  recorded**; input gate; **Sound not recorded**; gameplay-run build (`rev · dirty · wasm`, each
  "not recorded" when absent — current data has wasm only); ✓/✕/? gate chips; every unmet gate
  with status, summary and source; recorded blockers; why a recorded review is not current;
  next step; existing Launch actions and Details. Filters: all / reviewed gameplay / no blockers /
  ready. Sort: ready, reviewed gameplay, fewest blockers, fewest unmet gates.
- `release-readiness.js`: adds `staleReasons` (no reviewer, no date, basedOnRunKey not a reviewed
  gameplay run, newer failed gameplay, source hashes changed). Status logic unchanged.
- Logic in new UMD `ops/release-model.js` (served, loaded before app.js); a stale review's old gate
  summary is shown as "it said: …", never as a pass.
- Tests: new `ops/release-model.test.js` (6): unreleased-only + unknown rate, Flip-event rate never
  labelled frames/FPS, stale reasons, build identity never invented, rendered view escaping/unmet
  gates/launch states/filter (app.js executed in a vm with an inert DOM), script served.
- Real data via own server (8197): 103 unreleased, 62 with reviewed gameplay, 4 reviewed logical
  rates (cave-story 24.9, icy-tower 50.0, moorhuhn-2 8.0, moorhuhn-winter 36.4), gta2-demo
  29.9 guest Flip events/s (unreviewed); 4 stale reviews, reason: source hashes changed.

### 2. Exact-build Play (DASH-GAPS-PLAY-BUILD)

- `emulator-server.js`: `getBuildIdentity(root)` — SHA-256 of the served `build/wine-assembly.wasm`
  (cached by size+mtime), `git rev-parse HEAD`, tracked dirty-file count; `null` when git or the
  module is unavailable, never a guess. Exposed as `emulatorBuild` in `/api/state`.
- Available launch URLs gain `&build=<wasm sha256>`; the emulator index refuses with 409
  "Served build changed since the dashboard snapshot: link expects wasm X, now Y" if the module
  changed. The unavailable-app 409 now lists the missing files.
- UI: corpus launch bar states the served build once; candidate details and Ready rows show a build
  chip; unavailable routes list up to three missing files on the card (+N more → Details, full list
  open there); Ready rows say whether the served wasm matches the reviewed gameplay run's wasm.
- Tests: `emulator-server.test.js` +1 (identity without git / clean / dirty, pinned URL, 200 when
  equal, 409 after rebuild, 409 with missing paths); `release-model.test.js` +1 (served build text,
  match/differs/unknown, rendered chip, missing files on row, compact corpus cards).
- Real tree (own server 8197): rev 16f764ad, dirty (196 tracked files), wasm f40d4ca33822; pinned
  nfs2_demo link 200, wrong pin 409, snood 409 listing its two missing files.

### 3a. Cherry-pick of 63a248a6 (dependency)

`255aeab6` = `git cherry-pick -x 63a248a6` ("Show subagent summaries on parent dashboard cards",
author Codex, from `origin/ops/subagent-summaries-20261004`, which ops-dashboard is integrating).
Patch identical (4 files, +48/−2); the only conflict was both sides appending to the end of
`style.css`, resolved by keeping both blocks. Integrate in order, or drop together with commit 3.

### 3. Agents: one column, two lines (DASH-GAPS-AGENTS-2LINE) — depends on 3a

- `.agent-list` is one full-width column everywhere. `agentCard` is now a two-line row: line 1
  provider · short id · name · status word · `active Nm ago` (titled "activity is not proof of
  progress") · Terminal · ▸; line 2 decision reason / `Next:` / `Latest:` / "No result or next step
  recorded". Subagents: same two lines nested under the parent, three visible + "Show N more".
  Process, previews, token/timestamp meta and the old subagent block stay in the agent detail
  (which also gains Latest result and Parent session fields).
- Names: task title, else the task ID in the session prompt (`task CLAUDE-…`), else the title.
- A current subagent pulls its parent row in; parents are never duplicated; search matches children.
- Tests: new `ops/agents-view.test.js` (2): exactly 2 lines per agent and per subagent, nesting,
  collapse after 3, escaping, quiet-session wording, no process/preview/meta rows, single-column CSS,
  overview parent pull-in, search on children. Shared vm harness moved to `ops/test-app-vm.js`.
- Live state rendered through the new view (no browser): 3 top-level rows (Codex coordinator with
  3 children, Claude coordinator with 6, one history) — every row two lines.

### 4. Blockers: needs your input vs agent-resolvable (DASH-GAPS-BLOCKERS-SPLIT)

- `blocker-model.js` `actor(snapshot, task)` → `['user'|'agent', basis]` from recorded fields only
  (rule order in ops/README.md "Blockers and decisions"); `split()`; `blockerSummary()` adds
  `needsUser` / `agentResolvable` over primary roots (existing ordering kept).
- Web Blockers: "Needs your input" (live approvals + user roots) then "Agent-resolvable"; every
  blocker row (also Overview's Needs attention) carries a badge and its basis line.
- Telegram `/blockers`: second header line `N need your input · M agent-resolvable`, `NEEDS YOUR
  INPUT` / `AGENT-RESOLVABLE` groups, `Who:` basis per task; existing lines unchanged.
- Tests: `blocker-model.test.js` +1 (7 classification cases, groups, and web↔Telegram parity: same
  task IDs in the same groups and order, same counts); existing empty-summary expectation extended
  with the two new keys; `telegram.test.js` /blockers case asserts the groups and `Who:` line.
- Live state: needs input = RESOURCE-RECONCILE-REMOTE (existing "Capacity needed" rule: hosts),
  MIG-SAM-REP-RESTART (automated review); agent-resolvable = the two GAMEPLAY-* tasks
  ("no user decision").

### 5. Commit → pushed → merged → tested state (DASH-GAPS-CODE-STATE)

- `activity.js` `codeState()`: per listed commit `merged` / `pushed` (+ up to 5 remote branch names)
  / `local`, from `rev-list origin/HEAD` and `rev-list --remotes` (cap 20000, exact
  `merge-base --is-ancestor` fallback when capped; `branch -r --contains` only for pushed-not-merged,
  max 40), plus `FETCH_HEAD` mtime. No fetch, no network, no GitHub API, no tokens.
- Commit messages (subject + body) yield task-like IDs; `linkCommits()` keeps only real task IDs and
  attaches runs whose `build.commit` is that commit. Exposed as `commit.code/taskIds/runs`,
  `task.commits`, `codeState`.
- UI: Activity commit rows get chips (merged · origin/main | pushed · branch | local only; tested ·
  N runs | no run records this commit; **deployed: not recorded**; task links); task rows get a
  `Code:` summary line; task details a Code section.
- Tests: `activity.test.js` +1 (bare remote + clone: merged/pushed-to-branch/local, fetch time, IDs,
  run and task linking); `agents-view.test.js` +1 (chips, escaping, no deploy claim, task summary).
- Real repo (own server 8197): last 150 commits = 100 merged, 44 pushed, 6 local; 3 commits have a
  run recording them; no open task ID appears in those commit messages (honest empty state).
- Deploy per commit stays "not recorded": the only production evidence is the 2026-10-03 file
  snapshot (`ops/release-evidence/production-20261003/`), which names no commit.

### 6. Matched-scene performance comparison (DASH-GAPS-PERF-COMPARE)

- `release-model.js` `perfComparisons()`: newest measurement vs each earlier one; comparable only
  when metric, counterKind, scene, renderer, host and GPU are identical and both record
  `wasmSha256`; returns delta %, metric label, same/different build; everything else is listed as
  not comparable with the differing fields.
- Candidate details show a **Before / after** section (only when a measurement exists).
- Tests: `release-model.test.js` +1 (one comparable pair +25.0%, scene / missing-hash /
  counter mismatches named, single-measurement and no-match texts, rendered section).
- Live data: every measured game has exactly one recorded measurement (8 runs, 8 candidates), so
  each shows "Not comparable: only one measurement recorded"; no comparison is invented.

## Rebase onto origin/main 640b85a4 (delivery, 2026-10-05 02:4xZ)

Fresh worktree, branch `claude/dashboard-gaps-20261005-r2`. The commits were cherry-picked in
order and `255aeab6` was dropped, because the subagent summaries are already on main as
`7db978dd`. The original branch is untouched. There were two conflicts, both end-of-file appends
to `style.css`: both sides were kept, and main's existing `.subagent-summary` rules were not
duplicated.

### 7. Release counts, stale-review note, phone QA fixes

- Ready for desktop shows three counts, each a filter: **Playable unreleased** (reviewed gameplay
  screenshot plus a launch route available now), **Review needed** and **Ready**.
- A separate notice names the stale recorded release reviews and says why they are stale.
- Each row says "Deploy not recorded", and a note states that sound and deploy are not gates.
  No gate and no approval requirement were added.
- Live counts: 62 playable unreleased, 72 review needed, 0 ready. All 4 recorded reviews are
  stale: Cave Story, Icy Tower, Moorhuhn 2 and Moorhuhn Winter-Edition, because the runtime
  source hashes changed.
- QA fixes:
  - On a phone, an agent row wrapped to 8+ visual lines. The name is now one clipped line, line 2
    is clamped to two lines, and the short id is hidden on phone.
  - Codex children whose prompt starts with a `[Role]` label are now named by that label, not by
    the whole prompt.
- Tests: `release-model.test.js` +1 (counts, filter, stale notice, deploy text, no new gate) and
  `agents-view.test.js` extended (bracket label, phone clamp).

### Browser QA (root grant)

- Setup: one `ops/server.js` from this worktree on 127.0.0.1:8197 and one headless Chrome
  (puppeteer-core, `/usr/bin/google-chrome`). Two runs, about 15 s each. Live 8098/8099 untouched.
- Views: Overview, Agents, Ready for desktop, a title detail (abedemo), Blockers and Activity, at
  1440x900 and 390x844.
- Before fixes, `scratch/claude-dashboard-gaps-20261005/qa/20261005T024313Z/`:
  - Desktop: every agent and subagent line rendered as exactly one line; no horizontal overflow
    in any view.
  - Phone: agent rows wrapped up to 8 lines.
  - One console 404, which is `/favicon.ico`. That route was never served, so it is pre-existing
    and harmless.
- After fixes, `…/qa/20261005T024414Z/`: desktop unchanged; phone agent rows are bounded (name
    clipped, line 2 at most two lines); no horizontal overflow; no page errors.
- Both runs: Release, Blockers, Activity and the detail view showed no overflow at either size.
  `qa.json` in each folder holds the per-view measurements.
- After both runs, `pgrep` found no server, Chrome or QA process left.

## Tests

`node --test ops/<file>.test.js`, one file at a time in the worktree, at the final commit. The
shared checkout's `node_modules` is symlinked in and left untracked. Exit codes: activity 0 (5),
agents-view 0 (3), blocker-model 0 (5), coordinator-inbox 0 (10), dxball-frame-counter 0 (18),
emulator-server 0 (6), gameplay-coverage 0 (9), gameplay-frame-counter 0 (11),
icy-tower-frame-counter 0 (31), icy-tower-measurement 0 (21), ops 0 (27), release-model 0 (8),
release-readiness 0 (8), telegram 0 (24). terminal exits 1 with 3 pass / 2 fail: both failures
are browser cases that report `Browser was not found at the configured executablePath
(/Applications/Google Chrome.app/…)`. That is a macOS-only Chrome path in an environment
without Chrome. The failure predates this branch, and these commits don't touch that file.

New tests use `ops/test-app-vm.js`. It runs `task-ui.js`, `approval-ui.js`, `blocker-model.js`,
`release-model.js` and `app.js` in a vm with an inert DOM, so the views render against fixture
snapshots without a browser.

## Screenshots

None taken. Browser review needs a runtime slot (REQUEST → root grant → CLAIM → one Chrome →
RELEASE) and no grant was posted during this task. Real-data checks were made instead: a GET of
`/api/state` from my own `ops/server.js` on 127.0.0.1:8197 against the shared root, plus views
rendered from that snapshot in the vm. Still to do with a slot: Overview, Agents, a title's
details and Ready for desktop at desktop width and at 390 px. Check that the two-line rows hold
at ≥1000 px and wrap at 390 px, and that the ▸ and Terminal controls are ≥44 px on touch.

## Integration order

**Current (r2, base origin/main 640b85a4):** `fa678484` Ready for desktop → `313a69ae` exact-build
Play → `c12a662d` agents two-line → `625c25bc` blockers split → `dcd9578c` code state →
`d9bd42c0` perf compare → the release-counts/QA-fix commit that adds this paragraph. No
dependency on another branch.

Superseded original order (branch `claude/dashboard-gaps-20261005`, base dd0dd740):

`c78d985f` → `2996f415` → `255aeab6` (cherry-pick -x of 63a248a6, unmodified patch) → `a3eba543`
(depends on 255aeab6) → `5585d09c` → `246e9b83` → the perf-comparison commit. All are on
`claude/dashboard-gaps-20261005`, base origin/main `dd0dd740`, not pushed. If ops-dashboard has
already integrated 63a248a6, drop `255aeab6`: the only conflict was the shared end-of-file
append in `style.css`.

## Remaining gaps

- **Sound evidence:** there is no audio field in `result.json` and no sound gate, so the UI says
  "not recorded". Adding a sound gate would change the readiness rules, so it needs a decision
  from root or the user.
- **Deploy per commit:** the production snapshot holds files and names no commit. Showing
  "deployed" needs the deploy tool (`tools/deploy-berrry.js`) to record the commit and wasm it
  shipped.
- **Exact-build Play:** the launch serves the live tree. A pinned link refuses with an
  explanation when the module has changed, but it cannot replay an older build. That would need
  stored per-build artifacts.
- **Release reviews:** all 4 recorded reviews are stale because the runtime source hashes no
  longer match, so 0 games are "ready". The fix is a fresh review, not a dashboard change.
- **Task ↔ commit links:** these depend on commits naming task IDs. None of the last 150 commit
  messages name an open task. Agents should put the task ID in the commit message.
- **Not done (in the earlier review backlog but outside this scope):** deep links / routes,
  ETag/hidden-tab polling, public GitHub PR lookup.
