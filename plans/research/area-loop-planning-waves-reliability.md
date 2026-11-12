# Area research: task planning, Loop parallel waves, loop reliability, reviewer isolation (Tracks F, N, Y, U)

Research date: 2026-11-12. Code read at `origin/main` of `b1tninja/continuous`, commit `028a740` (after #674; the 2.15.0 cut is in progress and untouched by this note). Documents only: nothing was built, no model was called, `plans/ROADMAP.md` is not edited (the exact proposed text is in section 10). External sources were fetched or searched on 2026-11-12 unless a date says otherwise; anything that rests on a search snippet or a secondary page is marked **UNVERIFIED**.

Scope: ROADMAP Tracks F (task planning), N (Loop parallel waves), Y (loop reliability) and U (reviewer isolation and a cached review prefix). Not repeated here: the refusal rows RF1 to RF8 (`research/loop-refusal-detection.md`) and the loop UI pull requests in flight (#683, #687, #688, #694, #695, #697, #700, #701; #674 is merged). Where a row here touches those, the dependency is named and nothing is duplicated.

## 1. Findings in short

1. **Track F is further along than its table says, and one row is wrong.** F0 to F4 are built (F0 was replaced by a deterministic test, `plans/task-planning.md` Decision 1). **F7 is built** (`continuous plan list` and `continuous plan build`, `extensions/cli/src/commands/plan.ts`, `extensions/cli/src/plans/planStore.ts`, `planBuild.ts`, written 2026-11-11), but the ROADMAP row still says "Not started". F2 is half built (the strip, not the expand key or keyboard editing). F5 and F6 are open. The Track F table has no State column.
2. **The CLI's parallel waves do not use the worktree service the IDE uses.** `extensions/cli/src/loop/loopWave.ts` still creates its worktrees with `cn review`'s helper (`createWorktree` in `extensions/cli/src/commands/review/worktree.ts`: a detached worktree in the OS temp directory named `cn-review-<time>-<n>`) and applies patches with a bare `git apply`. `core/util/worktree.ts` (`createItemWorktree`, `applyPatch` with `touchedSince`, `listLoopWorktrees`, `.continue/worktrees.json` setup commands behind project trust) is reached only from the IDE through `loop/worktree*` messages (`core/core.ts`, `gui/src/redux/thunks/loop.ts`). So in the CLI and `cn serve`: no setup commands (a Node project's worker has no `node_modules`), no "changed in the checkout since the wave started" refusal, no `continued/loop-*` branch for N7 to list, and a crash leaves a `cn-review-*` directory in the temp folder that nothing removes. The comment in `loopWave.ts` ("until the core helper (L4 P2) lands") is stale: P2 landed. The ROADMAP rows N0, N6 and N7 do not say this. This is the largest new finding in Track N (row N0b below).
3. **A refused merge throws the worker's work away, and the item re-does it inline.** `finishParallelRun` (`core/util/loopMode.ts`) turns a `mergeFailed` result into `status: "pending"`, `runInline: true`, with the reason in the next prompt ("That copy is gone"). Nothing is parked (N3), no attempt is counted, and the whole item's tokens are spent twice. This is the cost blow-up of waves, and it is the single most valuable thing the first measurement (N1) can price.
4. **The "done" gate still has a hole for waves.** A worker's patch is applied to the person's checkout first and the item's `check:` runs there afterwards (`settleWorker` in `gui/src/redux/thunks/loop.ts`, `loopWave.ts`). A patch whose check fails has already changed the checkout. N5's "check in the worker's worktree before the merge" is therefore a safety row, not a nicety.
5. **Track Y has five unbuilt rows that need no new infrastructure** (Y1 to Y4 and Y0's settings control). A grep of `extensions/cli/src/loop/`, `core/util/loopMode.ts` and `gui/src/redux/thunks/loop.ts` finds no progress file, no clean-state check and no baseline run of the fallback check. A project whose tests already fail fails every item, and three failures in a row stop the loop (`plans/loop-reliability.md` section 6.1). Y4 is the smallest fix with the clearest user harm.
6. **Reviewer isolation (Track U) is mostly decided, and what is left is cheap.** U0 was measured (2026-11-10): the system-prompt cache marker alone (arm B) gave Nova 2 Lite 56% cache read with no loss of agreement; Haiku 4.5 reads 0% everywhere because the prompt is under its minimum. U1 was narrowed to arm B on 2026-11-11. U4 (isolation tests, offline) is the one worth doing now. Nothing in `core/tools/permissions/auto/review.ts` or `prompt.ts` sets a cache marker today (grep, 2026-11-12), so arm B is not built.
7. **The Loop does not use the stuck signals.** `core/util/stuckSignals.ts` and `workLog.ts` are used only by the CLI's chat notes (`extensions/cli/src/stream/stuckNotes.ts`, `repeatGuard.ts`); the loop's own stops are the repeat limit (4), the item-turn limit and the no-progress and 3-failure stops. That is row S5, outside this area, but it bounds what Y can promise.
8. **IntelliJ is missing 18 pass-through message types** that `core/protocol/passThrough.ts` lists (a script comparing the two lists, 2026-11-12): `subagents/list`, `models/serverConcurrency`, `models/detectLocal`, `models/catalog`, `config/setModelRoles`, `policy/load`, `policy/save`, six `audit/*`, `model/retirementNotice`, `model/dismissRetirementNotice`, `config/convertConnectionToAccount`, `openaiCompat/probeStatus`, `openaiCompat/testConnection`. N8 lists five; the true gap is wider and keeps growing, which argues for a test, not a list.

## 2. Verified state, row by row

States: **Built** (code on main matches the row), **Partly**, **Open**, **Stale** (the row or its claim no longer matches the code or the plan). Citations are paths under the repository root.

### 2.1 Track F: task planning

| Row | State                 | Evidence and what is left                                                                                                                                                                                                                                                                                                                                                                                                                                      |
| --- | --------------------- | -------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------- |
| F0  | Built, replaced       | `plans/task-planning.md` Decisions 1: the live Bedrock measurement became a deterministic test (`core/llm/llms/Bedrock.test.ts`, `packages/openai-adapters/src/apis/Bedrock.taskList.vitest.ts`). A live run with `Bedrock.cache.live.vitest.ts` is still "worth doing once" and is not recorded.                                                                                                                                                              |
| F1  | Built                 | `core/util/taskPlan.ts` (`buildTaskPlan`, validation, `keepOpen`, `lockChecks`), `Session.taskPlan` saved by `core/util/history.ts`, `gui/src/util/clientTools/taskListImpl.ts`, `extensions/cli/src/tools/taskList.ts`, the tail block placed after the cache point.                                                                                                                                                                                          |
| F2  | Partly                | `extensions/cli/src/ui/components/TaskProgressStrip.tsx` (55 lines): the one-line strip and the plan file name. No expand key and no keyboard editing: the file has no key handler. `plans/task-planning.md` says the key "must not clash with existing bindings; not checked". No `ctrl+t` handler exists in `extensions/cli/src/ui` (grep), and Claude Code and Gemini CLI both use Ctrl+T for the same toggle (sections 7.1, and `plans/task-planning.md`). |
| F3  | Built                 | `gui/src/components/mainInput/TaskListPanel.tsx` has in-place `<input>` editing; `buildChatRequest.ts` carries `taskListMessage`; the person's edit wins (`updatedBy: "user"`).                                                                                                                                                                                                                                                                                |
| F4  | Built, name stale     | `core/util/planFile.ts`, `gui/src/util/clientTools/presentPlanImpl.ts`, `gui/src/pages/gui/ToolCallDiv/PlanCard.tsx`, the CLI `PresentPlan`. The directory is `PLANS_DIR = ".continuous/plans"` (`core/util/planFile.ts:44`); the ROADMAP row and the earlier text of `task-planning.md` still say `.continue/plans/`.                                                                                                                                         |
| F5  | Open                  | No code copies `taskPlan` into a new session (grep of `gui/src`, `extensions/cli/src`, `core`: `ColdCacheNotice.tsx` has no plan text; `thunks/session.ts` only saves). No block-completion setting: `keepOpen` in `taskPlan.ts` is something else (a partial list from Build keeps the open items). C6 (the cold-cache notice) is built, so F5 is unblocked.                                                                                                  |
| F6  | Open, mostly subsumed | Subagents exist (`core/subagents/`) but carry no plan down or summary up. Loop mode already gives a fresh context per item and waves give a context per worker, so the plan-execution use of subtasks is covered; what remains is Track O (agent definitions).                                                                                                                                                                                                 |
| F7  | **Built (stale row)** | `extensions/cli/src/commands/plan.ts` (`planListCommand`, `planBuildCommand`, `registerPlanCommand`, the once-per-change resume offer `offered?.[p.file] !== p.modifiedMs`), `extensions/cli/src/plans/planStore.ts`, `planBuild.ts`; page `docs/ide-extensions/agent/plan-files.mdx`; `plans/task-planning.md` "Plan commands (F7)". Not built: the IDE start-up notice for a plan with open steps (no counterpart in `gui/src` or `core`; grep).             |

### 2.2 Track N: Loop parallel waves

| Row | State               | Evidence and what is left                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                       |
| --- | ------------------- | ------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------- |
| N0  | Partly, understated | Built: `--internal-loop-worker` (`extensions/cli/src/index.ts`), `loopWave.ts`, `loopWorker.ts`, `loopItemRun.ts`, the wave step in `serve.messages.ts` (line 444, `step.kind === "wave"`), `loopParallel` in `serve.loop.ts`, the CLI `LoopInbox.tsx`, six flow tests in `loopWave.test.ts`. The `/state` snapshot lists the wave only if `serve.loop.ts`'s state fields do; not traced. What the row misses: the CLI wave runs on the legacy `cn review` worktree helper (finding 2). Also, the usage message handler reads `input.loop.current?.itemId`, which is correct only because each worker input is a one-item loop. |
| N1  | Open (run 7 exists) | `plans/loop-mode.md` "Parallel waves (run 7, 2026-11-09)": one run on Strata, 3 of 3 done, no patch refused, 90% cache over 55 requests (shared server), "wall time against waves off: not measured". Nothing measures refused patches, undeclared files or the cost of an inline re-do.                                                                                                                                                                                                                                                                                                                                        |
| N2  | Open                | `applyPatch` (`core/util/worktree.ts`) checks only `touchedSince`. `patchFiles(patch)` exists (line 171) and `declaredPathKey`/overlap helpers exist in `core/util/loopMode.ts` (lines 874 to 920) but no code compares a patch's files with the item's `files:`.                                                                                                                                                                                                                                                                                                                                                               |
| N3  | Open                | Nothing parks a patch. The IDE drops it with the worktree (`settleWorker` comment "A stopped worker's changes are dropped"); the CLI `cleanupWorktree` removes it.                                                                                                                                                                                                                                                                                                                                                                                                                                                              |
| N4  | Open, deliberately  | Workers refuse a call that would ask (decision "no questions mid-run for workers"). Under IDGAF nothing asks (#687, in flight), so the cost falls on Supervised, Auto and Unattended only; and waves are off under Supervised.                                                                                                                                                                                                                                                                                                                                                                                                  |
| N5  | Open                | No `--3way`, no rebase, no pre-merge check (finding 4).                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                         |
| N6  | Partly              | Built for the IDE path only: `repoSetupCommands` in `core/util/worktree.ts` runs repository setup only when the `worktree` trust scope approves the exact content (`decideFromFiles`), the user's global `worktrees.json` runs unconditionally; the trust notice goes through `deps.notify` (a toast). Not built: the Node default and the inbox surface. **The CLI never runs setup commands** (finding 2), so in the CLI the trust question is moot and the Node problem is worse.                                                                                                                                            |
| N7  | Partly              | `listLoopWorktrees` exists (`core/util/worktree.ts:580`); its only caller is `removeStaleItemWorktree`, run before a new worktree for the same item (`core/core.ts:653`). No command, no Settings action. The CLI's `cn-review-*` leftovers are not listed by it (they are detached, branchless).                                                                                                                                                                                                                                                                                                                               |
| N8  | Open, wider         | 132 message types in `core/protocol/passThrough.ts` against 122 in `MessageTypes.kt`; 18 are missing (finding 8). `loop/worktree*` and `loop/dirtyFiles` are present, so IntelliJ waves work; subagents and local-server slots do not.                                                                                                                                                                                                                                                                                                                                                                                          |
| N9  | Open                | `models/serverConcurrency` is used by `gui/src/util/subagents/runSubagent.ts` and `core/llm/localServers.ts`; `LOOP_MAX_PARALLEL = 3` is a constant (`core/util/loopMode.ts:855`) and the wave chooser (`nextParallelItems`, lines 906 to 920) never reads the server.                                                                                                                                                                                                                                                                                                                                                          |
| N10 | Research            | Not started; its comparison point is `plans/loop-mode.md` and section 7.                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                                        |

### 2.3 Track Y: loop reliability

| Row      | State        | Evidence and what is left                                                                                                                                                                                                                                                                                                       |
| -------- | ------------ | ------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------- |
| Y0       | Built, no UI | `itemCheck(loop, task)` in `core/util/loopMode.ts`; `LoopState.fallbackCheck`; `gui/src/redux/thunks/loop.ts` lines 205 to 230 and 669; CLI `loopFallbackCheck.ts`, `CONTINUOUS_LOOP_FALLBACK_CHECK`, `serve.loop.ts`. The settings control in the webview is not built; #701 (settings dialog, in flight) is where it belongs. |
| Y1 to Y4 | Open         | Grep for `progress file`, `.progress.md`, `cleanState`, `dirty`, `baseline` in the three loop surfaces finds only usage-baseline helpers. The design is in `plans/loop-reliability.md` section 6.2.                                                                                                                             |
| Y5       | Open         | No verifier call and no goal-level done criteria (`plans/loop-mode.md` "Proposed: what does done look like").                                                                                                                                                                                                                   |
| Y6       | Open         | `freshContext` defaults to true (`core/util/loopMode.ts:803`); no experiment arm exists.                                                                                                                                                                                                                                        |
| Y7       | Built        | #551 (merged 2026-11-11). Row can say Built.                                                                                                                                                                                                                                                                                    |
| Y8       | Open         | Depends on Y5 and N2; `replanConcern` already refuses a re-plan that changes a failing check (the gate is held at the plan level; the in-run edit is not detected).                                                                                                                                                             |

### 2.4 Track U: reviewer isolation

| Row        | State            | Evidence and what is left                                                                                                                                                                                                                                                                                                                                                     |
| ---------- | ---------------- | ----------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------- |
| U0         | Built (measured) | `core/scripts/reviewerCacheProbe.mjs`, `evaluation/cacheProbe.ts`; result in the ROADMAP row (Nova 2 Lite B 56.2%, C 63.6%; Haiku 4.5 0% in all arms). One pass, Bedrock Converse only; Anthropic API and Claude 5.x models (512-token minimum) not run.                                                                                                                      |
| U1         | Open, narrowed   | `core/tools/permissions/auto/review.ts` and `prompt.ts` contain no cache marker and no cache option (grep). The review passes no cache setting; a marker comes only from the reviewer model's own entry (`plans/reviewer-audit.md` section 1, item 5). The static prompt (`REVIEWER_SYSTEM_PROMPT`) and a per-call nonce in the fence from the second block on are unchanged. |
| U2, U3, U5 | Parked           | As recorded 2026-11-11; nothing in the code contradicts that.                                                                                                                                                                                                                                                                                                                 |
| U4         | Open             | `reviewerAddressed.ts` and its corpus exist (a deterministic pre-filter for text addressed to the reviewer, measured on 16 injection cases), but no test pins "no tool output in a review request", and no injection set aimed at the reviewer's own prompt is in the B4 set beyond those 16.                                                                                 |

## 3. Track F: open rows in depth

### 3.1 F2b: expand the progress strip, then edit from the keyboard (S then M)

**Problem in user terms.** In `cn` a person sees "Tasks 3/8 Running migrations" and cannot see the other seven items without scrolling or asking the model. The IDE has the full list under the input.

**Design.**

- Step 1 (S): read-only expand. A key that toggles the full list under the strip: up to 12 lines, the in-progress item highlighted, completed items dimmed, "+ N more" beyond the cap (`formatTaskProgress` and `TaskItem` already carry the data). Key: **Ctrl+T**, the binding Claude Code and Gemini CLI use for the same view. Before choosing, grep every `useInput` handler in `extensions/cli/src/ui` for Ctrl+T and terminal conflicts (tmux uses none by default; unverified for Windows Terminal). Add a footer hint only while a list exists.
- Step 2 (M): keyboard editing: arrow keys select, `space` toggles completed, `e` edits text, `d` removes. Each edit calls the same `buildTaskPlan(..., {updatedBy: "user"})` path the IDE uses so the next request's block says the person edited it. The one race (a tool call generated before the edit) is the same one the IDE has and is accepted in `task-planning.md` Decision 2.
- Loop interaction: while a loop runs, `<LoopStrip />` replaces the strip (`ChatScreenContent.tsx` line 111), so F2b applies to plain chat only; the loop's own to-do tree is #694/#695.

**Alternatives rejected.** A permanent multi-line panel: costs terminal rows on every small screen. A slash command only (`/tasks`): invisible to people who do not know it, and Claude Code already uses `/tasks` for background tasks.

**Failure modes.** Ink input handlers fight the prompt editor for keys (the strip must only capture keys while expanded). Narrow terminals: truncate with `wrap="truncate-end"`. **Test plan.** `ink-testing-library` tests in the style of `TaskProgressStrip.test.tsx`: toggle, cap, narrow width, edit applies and sets `updatedBy`. **Size** S for step 1, M for step 2. **Acceptance.** Ctrl+T toggles; no conflict with the existing handlers; an edited item is reported to the model on the next request.

### 3.2 F5a: new session with this plan (M)

**Problem.** A long session with a cold cache is expensive to continue; the person wants a fresh session that carries the plan, not the transcript. Today the cold-cache notice (`gui/src/components/mainInput/ColdCacheNotice.tsx`) can only suggest starting over, and the plan is lost.

**Design.**

- Data: a new session gets `taskPlan` and `planFile` copied (both already on `Session`, saved by `thunks/session.ts` lines 260 to 261), a one-line first message ("Continuing earlier work on the plan in `<file>`; items marked completed are done; start with the first open item"), and nothing else. A saved session without these fields behaves as today.
- Entry points: (1) the cold-cache notice, as an action beside the existing one, shown only when `taskPlan` has open items; (2) the plan card's **Build** gets a second button **Build in a new session** (Claude Code's plan approval offers a fresh-context option; exact label **UNVERIFIED**, from memory of its interface, check `https://code.claude.com/docs/en/permission-modes` before copying wording); (3) after compaction, when the summary prompt reports open items. (2) is the one with clear user value and no cost estimate needed.
- CLI parity: `continuous plan build <file>` (F7) already is "a new session with this plan"; the IDE action should call the same seeding (`planBuild.ts` logic lives in the CLI; the IDE reads the file back in `buildPlan.ts`). Share the seeding function through `core/util/planFile.ts` instead of a second copy.
- Wording: "Continue in a new session" with the line "Starts empty and keeps your task list and plan file." Consistent with the loop UI's plain labels (no "fork", no "handoff").

**Alternatives rejected.** Carrying the summary as well: that is what compaction is for, and it re-creates the cost the person is trying to avoid. A server-side session handoff: Bedrock Converse has none (`plans/reviewer-isolation.md`).

**Failure modes.** The plan file moved or deleted: the new session starts with the list from `taskPlan` and shows "plan file not found". A plan file the person edited since: Build already reads the file back (`buildPlan.ts`). **Test plan.** gui redux test: new session carries `taskPlan`, `planFile`, no history; the first request's task block lists the items. **Size** M (three entry points, one shared seed). **Acceptance.** From a session with open items, one click gives an empty chat whose first request contains the list and the plan file path, and the old session is unchanged.

### 3.3 F5b: block completion while items are open (S, default off, defer)

Roo's `preventCompletionWithOpenTodos` (`plans/task-planning.md`) is the model. In a chat there is no "complete" call; the harness could append one reminder when a turn ends with an `in_progress` item and no tool call. Recommended default: **off, and not built in 2.16.0**: it adds a model request per turn end, it fights models that correctly end a turn to ask a question, and the Loop already has the real gate (`finish_item` plus checks). If built: one reminder per turn, never twice, never in headless `-p` runs, never in Loop.

### 3.4 F6: subtasks (drop as written)

The plan's reason (Roo's Orchestrator, Cursor Projects) is a fresh context carrying the plan down and a summary up. Loop mode delivers exactly that for plan execution (fresh context per item, `freshContext` default on) and waves deliver it in parallel. What remains is user-invoked delegation of one task list item to a subagent, which is Track O's agent definitions plus `TaskItem.model` (M2, shipped). Recommended: mark F6 "Superseded by Loop items and Track O"; do not schedule. Claude Code makes the same split: subagents for focused work that returns a result, "agent teams" (experimental, disabled by default) for coordinated work with a shared task list (https://code.claude.com/docs/en/agent-teams, 2026-11-12).

### 3.5 F7 leftovers and the table

- Restate the Track F table with a State column (F0 built-replaced, F1 built, F2 partly, F3 built, F4 built, F5 open, F6 superseded, F7 built; section 10).
- F7b (S): the IDE start-up notice for a workspace plan with open steps and no list loaded. The CLI does it once per change (`planStore.ts` "offered" record). The IDE needs a core message `plans/list` (reads `.continuous/plans`, reuses `planStore` logic moved to core) and a dismissible card above the input. Wording: "A plan in this folder has 3 open steps: `add-retry.md`. Open it, or ignore." Needs the same `PASS_THROUGH` entry on IntelliJ (N8). Not for 2.16.0 unless the IntelliJ test (N8b) lands first.

## 4. Track N: parallel waves in depth

### 4.1 Concurrency model (as built, and what changes)

As built: core's `decideNext` returns `run_parallel` with at most `LOOP_MAX_PARALLEL = 3` items whose `after:` is met and whose declared `files:` do not overlap, only at autonomy auto or above and when `LoopState.parallelOn` is set (`core/util/loopMode.ts` lines 855 to 920). Each worker has a fresh context, its own worktree and a one-item loop; workers settle one at a time (the `settling` promise chain in `gui/src/redux/thunks/loop.ts`; `Promise.allSettled` and per-result handling in `loopWave.ts`); the inline item waits until the wave is empty. Patches merge in finish order; a refused patch sends its item back to run inline.

This is the right shape and the external evidence supports it (section 7.2): every system that runs coding agents in parallel isolates them in worktrees, VMs or branches and leaves the merge to a person or a conflict-free split. It also matches Claude Code's own advice for agent teams: "Break the work so each teammate owns a different set of files" and "for sequential tasks, same-file edits, or work with many dependencies, a single session or subagents are more effective".

Changes proposed, in dependency order (all optional behind the existing switch; saved loops without the new fields load unchanged):

1. **One worktree service for both hosts (N0b).** Move the CLI wave to `core/util/worktree.ts` with `execFileGit` (the CLI already imports `core/dist`). Gets for free: `continued/loop-<slug>-<item>` branches (so N7 can list them), the baseline commit, `touchedSince`, setup commands behind trust, removal of a stale worktree for the same item. Replace `createWorktree(Number.parseInt(itemId, 10) || 0)`; that helper names directories by time and index, so two waves started in the same millisecond with ids that parse to the same number collide (not reproduced; read from the code). Verify `process.cwd()` handling when `cn` starts in a subdirectory of the repository: `git diff HEAD` output is relative to the repository root only with `--relative` absent; the worker's `process.chdir(worktree)` then lands at the root, not the subdirectory (**not tested**; first test to write).
2. **Undeclared-file policy (N2).** After the worker ends, compare `patchFiles(patch)` with the item's `files:` through the existing overlap helper (`declaredPathKey`). Three outcomes, a loop setting `waveUndeclared`: `"allow-disjoint"` (default, recommended, pending owner): accept a patch that touches undeclared files **only if** none of them is in another running or merged item's declared set, in the person's dirty set, or in the files this wave has already merged; the inbox row says "Changed files it did not declare: `x.ts`"; `"refuse"`: treat as a merge failure; `"off"`: today. A built-in ignore list strips lockfiles and build output from the patch before the check (`package-lock.json`, `pnpm-lock.yaml`, `yarn.lock`, `dist/`, `out/`, `*.tsbuildinfo`, `.next/`): a worker that ran an install would otherwise be refused for a lockfile it never meant to change. Rejected: refusing every undeclared file (workers add test files and helpers constantly; the first run would refuse most waves) and ignoring the check (the declaration is the only independence guarantee the harness has).
3. **Check before merge (N5a).** Run the item's `itemCheck` in the worker's worktree before applying its patch; a failing check returns the item to the worker's next attempt with the output, and **nothing** reaches the checkout. Needs deps in the worktree (N6). The check still runs once more in the checkout after the merge when the merged tree differs (another item's patch landed first): cheap, and it catches semantic conflicts between merged items. Rejected: running only in the checkout (today; leaves failed work applied).
4. **Park, don't drop (N3).** On a stop, a timeout or a refused merge, write the worker's `git diff` to `<git dir>/continued/parked/<slug>-<item>-<attempt>.patch` (inside the git directory so it never shows in `git status` and never gets staged), pass it through the at-rest secret scrubber the plan commands already use, and record `LoopItemState.parkedPatch?: { path, files, at }`. The item's next worktree is created and the patch applied to it with `git apply --check` first; if it applies, the worker continues from it (its prompt says "an earlier run's changes are already here; check what is done"); if not, the prompt names the path and the reason. This replaces the current prompt text "That copy is gone". Cleanup: at loop end and after 7 days; a Settings action lists them with N7.
5. **Retry on the merged tree (N5b), after N3.** A refused patch gets one retry: apply to a scratch worktree at the current checkout state with `git apply --3way`; success there goes through the same pre-merge check as 3. Failure parks the patch (4). Opt-in setting, off by default; rejected as default because a textually clean three-way merge is exactly where semantic conflicts hide (section 7.2: textual conflict rates are reported at 41.7% for cross-agent pairs and semantic ones are unmeasured).
6. **Wave size follows the server (N9).** `size = min(LOOP_MAX_PARALLEL, serverConcurrency.slots)`; a one-slot local server never starts a wave and the status line says "Waves off: the model server has one slot" (wording for #697's status line, #700's tray only for needs-you items). The CLI needs the same query the IDE's subagent runner uses; where it cannot get one, keep 3 and say so.

### 4.2 Isolation model

Git worktrees, one per worker, from HEAD plus the checkout's uncommitted diff and untracked non-ignored files (`createItemWorktree`), a baseline commit so `worktreePatch` is the worker's own changes. What a worktree does not isolate: the ports, the database, the package manager's global cache, `node_modules` if linked, the user's home directory, other worktrees through absolute paths (IDE absolute paths stay unconfined, `plans/loop-mode.md`). The ROADMAP's sandbox rows (Track W, SB) are where confinement belongs; this note only flags that a wave multiplies whatever a single run can do by up to three.

**N6 Node default, with its hazard.** A default setup for a repository with `package.json` and no `worktrees.json`: link `node_modules` from the root. Hazard: `npm install` run by a worker writes **through** the link into the root `node_modules` (a shared mutation outside the patch). Mitigations: link only when a lockfile exists and the install is not expected (declare it in the inbox: "Worktrees share your node_modules"), and add the worker prompt line "do not install packages; if you need one, finish the item as waiting". Alternative: `npm ci --prefer-offline` per worktree: correct and isolated, costs minutes and disk per worker; offer as the documented `worktrees.json` example, not the default. On Windows use a directory junction (no elevation needed), elsewhere a symlink. Surface any setup failure as an inbox row, never a silent fall back to inline (the row's own wording).

### 4.3 Conflict detection and merge-back strategy (summary)

| Layer                  | When               | Today                                     | Proposed                                                                          |
| ---------------------- | ------------------ | ----------------------------------------- | --------------------------------------------------------------------------------- |
| Declared overlap       | before the wave    | `files:` globs must not overlap (core)    | unchanged                                                                         |
| Undeclared files       | at settle          | not checked                               | N2 policy                                                                         |
| The person's own edits | at settle          | `touchedSince` (IDE only)                 | both hosts via N0b                                                                |
| Textual conflict       | at apply           | `git apply --check`, refuse               | N5b opt-in 3-way on a scratch tree                                                |
| Semantic conflict      | after apply        | the item's check, in the checkout         | N5a check in worker tree, then re-check in checkout when other items merged first |
| Lost work              | on refusal or stop | dropped                                   | N3 parked patch                                                                   |
| Leftovers              | after a crash      | IDE: removed on next run of the same item | N7 list and remove, both hosts                                                    |

### 4.4 Budget accounting per wave

What exists: worker usage reaches the loop through `recordWorkerUsage` in `loopWave.ts` (deltas via `usageSince`, `trackSessionUsage`), then `stopWaveIfOverBudget` aborts workers when the loop-wide token budget is hit; `finishParallelRun` adds per-item tokens and wall time (`addItemUsage`). The loop's time budget is elapsed time since `startedAt` (`loopBudgetStop`), so three parallel workers do not triple-count wall time, correct. Per-item dollar budgets are enforced while the cost is known (`loopCost.ts`, #476); a loop-wide `maxCostUsd` is not built (T0), and the CLI enforces only a mid-turn turn limit inside the worker.

Gaps and proposals:

- **Reserve before the wave starts (N12, S).** The T6 split strategies (`loopBudgetSplit.ts`) give each item a share. Before starting a wave, sum the shares of the chosen items; if the remaining loop budget is less than that sum, shrink the wave to what fits and say so ("Waves of 2: 3 would not fit the token budget"). Without it three workers can each be inside their own item budget and together overshoot the loop's in the same minute.
- **Cost, not only tokens.** A worker may run on an item's own `model:`; its cost is priced by that model. Use `loopCost`'s "cost unknown never counts as zero" rule for the wave too.
- **A refused patch is spent budget twice.** Count the worker's tokens against the item even when the patch is parked or dropped (today `addItemUsage` runs before the `mergeFailed` branch, so it is counted; keep it) and show the figure in the row so the person sees what waves cost: "Ran in parallel, 41k tokens, changes not merged".
- **The 15x figure.** Anthropic reports multi-agent systems use about 15x the tokens of a chat (section 7.2). Default stays off and under Supervised never on.

### 4.5 Failure modes

| Failure                                                              | Today                                                                                     | Mitigation                                                                                             |
| -------------------------------------------------------------------- | ----------------------------------------------------------------------------------------- | ------------------------------------------------------------------------------------------------------ |
| Two workers edit the same file that neither declared                 | the second patch is refused (textual) or silently merges (disjoint hunks, semantic clash) | N2 policy, N5a check on the merged tree                                                                |
| Worker killed (30-minute timeout, `LOOP_WORKER_TIMEOUT_MS`)          | counts as an attempt, work lost                                                           | N3 parks the patch; the timeout should be a loop setting and scale with the item budget                |
| The CLI process dies mid-wave                                        | `cn-review-*` directories and registered worktrees remain                                 | N0b branch naming plus N7 list; on `cn serve` start, remove loop worktrees whose loop no longer exists |
| A worker needs approval                                              | refused, the model works around it or fails                                               | N4 later; for now `grants carry into workers` (below)                                                  |
| Setup commands fail or are untrusted                                 | IDE: toast only; CLI: not run                                                             | inbox row, wave falls back to inline with a reason                                                     |
| Reload of the IDE during a wave                                      | `removeStaleItemWorktree` before the next create                                          | keep; N3 should park what that removal would delete                                                    |
| A setup command or worker hook has side effects outside the worktree | possible                                                                                  | trust gate already; document                                                                           |
| The wave finishes while the person typed in the same files           | `touchedSince` (IDE), none in CLI                                                         | N0b                                                                                                    |

**Grants carry into workers (S, to verify first).** `loopGrantKey` keys a grant on the command or resolved path, so an approval the person gave to an earlier inline item could cover the same command in a worker. Whether the CLI worker receives those grants was not traced (`loopWorker.policy.test.ts` is the place to check). If it does not, passing them is the cheapest answer to most of N4's problem and should be measured before building N4.

### 4.6 N1 first: what the measurement must record

Run order: N1 before N2, N3 and N5, because three of them are priced by it. Scenario `loop-wave-*` (new, in `bench/scenarios/`, seed `bench/seed/loopsbx/`): (a) two disjoint items, (b) three items one of which declares less than it touches, (c) two items that both edit one undeclared helper, (d) an item whose check fails in the worker tree. Record per run: items done, patches refused and why, tokens per item, tokens spent on re-done work after a refusal (the number N3 and N5 exist to cut), wall time against the same plan with waves off (run 7 did not measure it), cache read share per request, and the number of calls refused because they would ask (the number that decides N4). Decision rule: N3 and N5 are built if refusals or re-done work exceed 10% of a wave's tokens; N4 if at least one item in five fails on a refused call; waves stay off by default unless wall time falls by 25% at no more than 1.3x the tokens (all thresholds proposed, pending owner).

## 5. Track Y: loop reliability in depth

### 5.1 Y4 first: a baseline run of the fallback check (S)

**Problem.** The fallback check holds every item with no `check:` to one command. If that command already fails when the loop starts (a red test suite, a missing tool), every item fails its check, three failures in a row stop the loop (`LOOP_LIMITS`/failure stop), and the person sees "stopped" with no useful reason.

**Design.** At loop start, when `fallbackCheck` is set, the host runs it once through the same permission decision and runner as an item check, and stores `LoopState.fallbackBaseline?: { status: "passed" | "failed" | "refused"; exitCode?: number; tail?: string; at: string }` (optional, absent in saved loops). Outcomes: passed: go on. Failed: the loop does not start; the plan card shows "The check `npm test` already fails before any item runs. Fix it, pick another check, or start without one" with three actions (Start without a fallback, Edit the command, Start anyway). **Start anyway** records the baseline output tail and makes the fallback advisory (an item ends "done (unverified)" instead of failing), because an exit code cannot say whether the same tests still fail. Refused (policy refuses the command): the same card with the reason. Wording matches the plan card's other confirmation steps (#694) and the settings field in #701.

**Alternatives rejected.** Parsing test output to diff failing sets: framework-specific, brittle (Jest, node:test, pytest, cargo differ), and the loop already treats the command as an exit-code oracle. Auto-detecting a test command: the project's declared command is better evidence and Ralph's `AGENTS.md` validation commands show the pattern (`plans/loop-mode.md`).

**Failure modes.** A check that takes minutes delays the start (show "Running the check once before starting"; the 10-minute CLI limit applies); a check that is flaky passes at baseline and fails later (unchanged behaviour); a headless run with a refused command (`cn serve`) cannot ask: it reports `fallbackBaseline.status: "refused"` in `/state` and starts without the fallback only if `loopFallbackCheck` was sent with a new `loopFallbackBaseline: "skip"`. **Test plan.** Core: `decideNext` returns a `baseline` action before the first run when set and unrun; CLI flow test in `loopDriver.test.ts` with a scripted runner (passes, fails, refused); gui `LoopMode.test.tsx` for the three actions. **Size** S to M (the action plus the card). **Acceptance.** A repository with a failing test suite and `fallbackCheck` set never spends a model turn before the person decides.

### 5.2 Y0 control and Y2 clean-state note (S each)

- Y0 control: a "Check every item with" field in #701's settings dialog and the plan card, with an example placeholder from `package.json` scripts when present. Without it the feature is reachable only through an environment variable, `cn serve` JSON or a hand-built loop.
- Y2 clean state: after a passed check, `git status --porcelain` (CLI: the same runner as checks; IDE: `ide.subprocess`, which reports pass or fail only, so use `loop/dirtyFiles`, already a core message, `core/util/worktree.ts` `dirtyFiles`) records `LoopItemState.dirty?: string[]` (capped at 20 paths). Shown as "left uncommitted: ..." in the plan block for the **next** item (so it does not rediscover the files) and on the finished item's row. Off by default (`loopMode.cleanState`), because the plan decided "no commit per item". It informs; it never blocks.

### 5.3 Y1 and Y3: a harness-written progress file and handoff (M)

**Problem.** Three independent harnesses use a file the next context reads (Anthropic's progress file and JSON feature list, Codex's documentation file, Ralph's `IMPLEMENTATION_PLAN.md`; `plans/loop-reliability.md` section 2). Our state lives in the session JSON; the model-written `summary` is clipped to 160 characters in the plan block, so a fresh context learns little about what the last item did or what its check showed, and a person cannot read the loop's history without opening the session.

**Design.** Append-only `.continuous/plans/<slug>.progress.md`, written by the host after each item ends (never by the model; it never edits it), one block per run:

```
## Item 3: Add retry to fetch (done, attempt 2 of 2, 4 min, 31k tokens)
Check: `npm test -- retry` exit 0
Last output: (20 lines)
Changed: src/fetch.ts, src/retry.ts
Left uncommitted: (Y2, when on)
Summary: (the model's report, up to 500 characters)
Notes for later items: (the model's notes)
Next: item 4 (after 3)
```

The next item's first message names the path ("Progress so far is in `<file>`; read it before you start") and the plan block shows the previous item's check tail (Y3). The loop never reads the file back into decisions; the session stays authoritative. Plan files go through the at-rest secret scrubber and the project `.continuous` lock rules (#543 locks the project folder except `plans/`, so the file is writable where the plan is; confirm in `docs`). Size cap: 200 KB per file, oldest blocks folded to one line each.

**Alternatives rejected.** JSON for the model to edit: Anthropic's reason (the model is less likely to overwrite JSON) applies only when the model edits the file. Writing into the plan file's checkboxes: the plan file is the person's; `plan build` already writes checkbox markers there (F7), and mixing history in would break round trips. A database: nothing else reads it.

**Failure modes.** Two loops on one plan write the same file (per-loop file name suffix `<slug>.<loop id>.progress.md`); a read-only workspace (skip with one warning); the file grows beyond a fresh context's budget (fold, cap). The IDE writes through `ide.writeFile`; the CLI through `fs`. **Test plan.** Core: pure `renderProgressBlock(item, run, check)` with golden output; CLI flow test appends three blocks across three items and a restart; gui test that the first message names the path. **Size** M. **Acceptance.** After a three-item loop, the file has three blocks a person can read, and the fourth item's first request names it.

### 5.4 Y5 and Y8: verifier and test tampering (M, M; later)

Y5 splits in two. **Goal-level done criteria** (Plan-file `done:` lines, `plans/loop-mode.md`) is a plan-format change that needs the owner's yes; **a read-only verifier for items with no runnable check** is a model call per item and should start as a **shadow verifier**: run it, record its verdict beside the harness's, do not act on it, and measure agreement on the bench loop scenarios before it gates anything (the same pattern as the reviewer's shadow mode, #584). Y8 (edits to files a `check:` references inside an item's run): implement as a pure function over the item's patch and the check command's referenced paths (`npm test -- retry` references `retry*` test files by the declared `files:` only if the item declared them), flagged in the row as "Edited a file its check runs: `retry.test.ts`" and counted in the loop's report, not blocked. The evidence that it matters: three of six sandbox runs weakened a check on re-plan (`replanConcern` comment) and Anthropic's harness lets coding agents change only the `passes` field for the same reason.

### 5.5 Y6: experiments (paid, later)

Three arms from `plans/loop-reliability.md` section 7, now with a scenario home: fallback on/off, fresh context vs compaction per item, 4/8/16 items. Use the cross-model scenario harness (section 6), n of at least 10 per cell with Wilson intervals (`bench/src/sampleSize.mjs`), and label anything under 10 per arm "screening" (#517). Do not run before Y4 (otherwise the baseline failure contaminates the arms).

## 6. Test plan: a deterministic scenario harness for the loop

There are three layers today: scripted flow tests (`loopWave.test.ts`, `loopDriver.test.ts`, `serve.loop.test.ts`, `LoopMode.test.tsx`), the model benchmark (`bench/runner.mjs`, scenarios `loop-basic`, `loop-fix-forward`, `plan-deps`, `stuck-decoy`, seed `bench/seed/loopsbx/`), and one-off sandbox runs. What is missing is the layer between: scenarios **without a model** that assert loop invariants over scripted workers and a real git repository, and the same scenario files run on N models.

**Proposal: one scenario file format, two executors.**

- A scenario is JSON in `bench/scenarios/loop-*.json`: seed repository (the existing `loopsbx` or a variant), a plan file with `after:`/`files:`/`check:`, per-item scripted behaviour for the deterministic executor (edit these files, finish with this outcome, take this long, ask this call), and expectations (items done, patches refused and why, tokens within a band, final checkout state equals X, no `cn-review-*` or `continued/loop-*` leftovers, files untouched).
- Executor 1, deterministic (CI, free): the loop core and the CLI driver with `setLoopWaveDeps` fakes **but a real temporary git repository and the real worktree service**, so patch application, `touchedSince`, parking and cleanup are exercised for real; scripted workers write files and report. Catches the failure modes in 4.5 with no model.
- Executor 2, live: the same scenario run through `cn serve` on a matrix row (`bench/matrix.yaml`), scored by `score.mjs`. A model changes the numbers, never the expectations; a scenario that only a model can fail (undeclared files, a weakened check) has its deterministic twin that scripts the same behaviour.
- Cross-model use: one scenario, k models, same seed, the scorecard compares items done, refused patches, re-done tokens, cache share (the harness idea in the owner's memory notes, "cross-model scenario harness and 60 run results", is the right predecessor; its location is the session scratchpad, not the repository, so it needs porting into `bench/`).
- Scenarios to add first: `loop-wave-disjoint`, `loop-wave-undeclared`, `loop-wave-refused-merge`, `loop-wave-check-fails-in-worktree`, `loop-wave-killed-worker`, `loop-baseline-red`, `loop-progress-file`, `loop-dirty-state`, `loop-reviewer-isolation` (a review request built mid-loop contains no tool output).

Acceptance: the deterministic executor runs in the CI suite in under a minute, each scenario names the row it protects, and every proposed row below has at least one scenario.

## 7. External research

Fetched or searched 2026-11-12 unless stated; "snippet" means from a search result only (**UNVERIFIED**).

### 7.1 Plans and task lists

- **Claude Code.** Plan mode writes a plan and presents it for approval; the built-in Plan subagent is "a research agent used during plan mode to gather context", with Write and Edit denied; a subagent in a plan-mode session stays in plan mode; `ExitPlanMode` is removed from subagents unless their permission mode is `plan` (https://code.claude.com/docs/en/sub-agents). Agent teams (experimental, off by default) share a task list with three states and dependencies, claim with file locking, and gate completion with `TaskCompleted`, `TaskCreated` and `TeammateIdle` hooks (exit code 2 blocks and sends feedback) (https://code.claude.com/docs/en/agent-teams). Task list display and compaction behaviour: `plans/task-planning.md` Decisions (read 2026-11-06).
- **Roo Code, Gemini CLI, Cline, Cursor, OpenCode:** `plans/task-planning.md` records each (read 2026-11-03 and 2026-11-06); no change found today. Roo's `preventCompletionWithOpenTodos` is the model for F5b.
- **Cursor cloud agents** run in isolated VMs with the repository cloned and secrets, work on a separate branch, push for handoff, "merge-ready PRs with artifacts", parallel without a stated cap; the page names no review feature (https://cursor.com/docs/cloud-agent).
- **Cline subagents** (`spawn_agent`): own context window each, several at once, the parent waits for reports; edits in Act mode, most file changes blocked in Plan mode; no MCP tools; CLI and Desktop only, not the VS Code or JetBrains extension; "approving the spawn approves everything the subagent does" (https://docs.cline.bot/features/subagents).
- **Codex.** One third-party review of the desktop app (launched 2026-02-02 per that source) says each thread gets its own worktree and merging back to the main branch is manual; no official page confirming an automatic review agent was found in this search (**UNVERIFIED**; snippet: https://verdent.ai/guides/codex-app-first-impressions-2026). `plans/loop-reliability.md` records OpenAI's long-horizon recipe (milestones small enough to finish in one loop, validation commands per milestone, a shared documentation file).

### 7.2 Parallel agents

- **Subagent mechanics.** Claude Code: `isolation: worktree` gives "an isolated copy of the repository"; removed automatically if unchanged; Bash commands that redirect git into the main checkout are blocked; default 20 concurrent subagents (`CLAUDE_CODE_MAX_CONCURRENT_SUBAGENTS`), nesting to three layers; each subagent starts fresh and returns a summary (https://code.claude.com/docs/en/sub-agents). Compare ours: 3 workers, depth 1, patch merged by the harness.
- **When parallelism helps.** Anthropic's research system: agents use about 4x, multi-agent about 15x the tokens of chat; token usage explained about 80% of the variance on BrowseComp; poor fits "tasks needing shared context or many inter-agent dependencies, such as most coding work"; over-delegation (50 subagents for simple queries) and vague delegation causing duplicated work are named failures (https://www.anthropic.com/engineering/multi-agent-research-system). Cognition: share full context, because "actions carry implicit decisions" and parallel agents make conflicting ones; the default recommendation is a single-threaded linear agent, with a model that compresses history for very long tasks (https://cognition.com/blog/dont-build-multi-agents, the page is dated 2025). Claude Code's own team guidance: start with 3 to 5 teammates, 5 to 6 tasks per teammate, avoid same-file edits, begin with research and review (agent-teams page above). Our design (declared disjoint files, at most 3, off by default) is the conservative reading of all three.
- **Conflict evidence.** A study reported in secondary write-ups, arXiv 2607.04697 (33,596 agent pull requests, 716 replayed three-way merges), gives a 41.7% **textual** conflict rate for cross-agent pairs and measures no semantic conflicts; the authors call the textual figure a conservative lower bound. Another source cites "CodeCRDT" at 5 to 10% semantic conflicts on an older model (Claude Sonnet 3.5, October 2025) and a "60 to 70% reduction from typed interface contracts" that appears only in a blog (**UNVERIFIED**). Worktrees remove file collisions during work and move conflicts to merge time (agentpatterns.ai and Augment Code guides, via search, **UNVERIFIED**). Reading: declared files and a check on the merged tree (N2, N5a) address the two failure classes the evidence does name; nothing measured here says a three-way merge is safe, so N5b stays opt-in.

### 7.3 Review and verification

- **Reviewer isolation.** `plans/reviewer-audit.md` section 4 (read 2026-11-10): Anthropic's auto-mode classifier sees only user messages and tool calls, "reasoning-blind by design", because tool results are where injections enter (https://www.anthropic.com/engineering/claude-code-auto-mode); Codex's reviewer gets a compact transcript with hidden reasoning excluded and may run read-only checks (https://learn.chatgpt.com/docs/sandboxing/auto-review.md, 2026-11-10). Claude Code agent teams add a related rule: a message between agents is marked as coming from another session, cannot supply consent, and in auto mode is reviewed before delivery (agent-teams page).
- **Command gates.** Aider runs a configured lint command after every edit and, with `--auto-test`, the test command, then tries to fix reported errors (https://aider.chat/docs/usage/lint-test.html). Claude Code's `TaskCompleted` hook, Kiro, `/goal` and Codex per-milestone validation are the same shape (`plans/loop-reliability.md` section 3).
- **Stuck detection.** OpenHands' `StuckDetector` has five patterns (repeated action-observation, repeated action-error, monologue, alternating ping-pong, repeated context-window errors) with thresholds 4, 3, 3 and 6 cycles; thresholds are hardcoded in the version the issue describes (https://docs.openhands.dev/sdk/guides/agent-stuck-detector; GitHub issue software-agent-sdk#762, via search). Our `stuckSignals.ts` carries eight signals and S9 already proposes the 6-cycle test.

### 7.4 Reliability literature

- **MAST** (Cemri et al., arXiv 2503.13657, NeurIPS 2025 Datasets and Benchmarks): 14 failure modes in three groups; failure rates of 41% to 86.7% across seven open-source multi-agent systems; task verification and termination is 23.5% by summing premature termination 6.2%, no or incomplete verification 8.2% and incorrect verification 9.1%; step repetition 15.7% (figures from search summaries; one blog gives 21.3% for the group and looks inconsistent with its own sub-values, so check the paper before quoting) (https://arxiv.org/pdf/2503.13657.pdf).
- **Premature "done" and under-verification:** Anthropic's long-running harness lists "declares the project finished too early" and "marks features done prematurely" (https://www.anthropic.com/engineering/effective-harnesses-for-long-running-agents, 2025-11-26); `plans/loop-reliability.md` section 3 adds ADaPT (+30 points of inflated self-reported success), a study of 16,991 SWE-agent trajectories (arXiv 2604.02547, abstract only) and agent-written tests adding marginal value (arXiv 2602.07900).
- **Doom loops on small open models:** SWE-Gym (open 32B model trapped in 29.4% of SWE-bench Verified tasks, arXiv 2412.21139), SWE-Bench Pro (Qwen3 32B tool error rate 42.0%, arXiv 2509.16941), SWE-EVO (arXiv 2512.18470): `plans/loop-reliability.md` section 4. Our own measurement: 12 `finish_item` calls in 1,113 steps in one recorded local session.
- **Evaluation method.** Anthropic's research system: about 20 representative queries suffice when effect sizes are large; judge outcomes, not paths; for stateful tasks evaluate the end state at checkpoints. That is the shape of the scenario harness in section 6 (expectations on end state, not on the route).

## 8. Track U: reviewer isolation and the cached prefix in depth

### 8.1 What the reviewer should and should not see

The current design is right and should be pinned by tests (U4):

| Sees                                                                                 | Does not see                                                                                                  |
| ------------------------------------------------------------------------------------ | ------------------------------------------------------------------------------------------------------------- |
| The person's last 10 messages (`MAX_USER_MESSAGES`), clipped                         | Tool output of any call (only `outputFlagged`, a boolean marker)                                              |
| Names and clipped arguments of the last 30 earlier calls (`MAX_TOOL_CALLS`)          | The agent's prose, reasoning, plan or task list                                                               |
| Environment (trusted domains, production markers, remotes) and the person's guidance | Earlier verdicts or any other review (`state.cached` is an exact-repeat lookup returning a verdict, not text) |
| The call under review, fenced, declared untrusted data                               | A provider conversation id or thread                                                                          |

Why: persuasion by the author's reasoning, prompt injection through tool output, and context bleed between reviews; the plan, `reviewer-audit.md` section 4 and Anthropic's published auto-mode design agree (section 7.3). Two refinements to record as decisions: **(a)** the loop's plan block and item goal are _not_ given to the reviewer. A reviewer that knows the item's goal could judge "does this call serve the goal", but the goal text is model-influenced (plans can be edited by the model at re-plan) and the person's messages already carry the intent; revisit only with data from shadow mode (#584). **(b)** a review of a **worker's** call (a wave) carries the worker's agent identity in the audit record (#576) and the same digest built from the worker's own history, never the parent's.

### 8.2 Cached review prefix

Decision as recorded: do **arm B only** (cache marker on the system prompt) and park the reorder (U1 narrowed 2026-11-11). Concretely (S):

- Where: `reviewCompletionOptions` in `core/tools/permissions/auto/review.ts` today sets temperature, token limit and reasoning, and no cache setting. Add a per-request cache hint for the system message only where the reviewer model's family supports it, behind the model entry's existing `promptCaching` setting being unset (a person who set it keeps theirs).
- Guard: a minimum-size check using the shared minimums in `packages/llm-info/src/promptCache.ts`. Do not send a marker on a prompt under the model's minimum: the ledger would claim a cache that is not there (Haiku 4.5 at 4,096 reads 0% in every arm).
- Do not vary reasoning or effort between reviews on a family where those invalidate the system level (`plans/reviewer-audit.md` section 3).
- Test: unit test on request building (marker present on a model whose minimum the prompt clears; absent under it; absent when the model entry sets caching off); no live call.
- Expected value is small (a 4,000-token review costs about $0.0004 at $0.10 per million input tokens, `plans/reviewer-audit.md` section 5); the real prizes are latency on a blocking call (median 1,106 ms uncached against 955 ms with arm B on Nova 2 Lite in the measured pass) and rate-limit relief on Bedrock. Hence: ship arm B behind the existing setting, no new UI, and stop there unless a bench run shows reviews above 5% of a run's cost.

U1's full reorder, U2, U3 and U5 stay parked for the reasons in the ROADMAP; this note found nothing that reopens them. One addition to U3's reasoning: a provider thread would put one review's text (possibly attacker-written arguments) into the next review's context, which is the property the feature exists to avoid.

### 8.3 U4: isolation tests (S, offline)

1. **No tool output in a review request.** A test builds a session history containing a tool result with a distinctive marker string, calls `buildReviewMessages`, and asserts the marker appears nowhere in either message (and that `outputFlagged` is the only trace). Also for the CLI and IDE adapters that assemble `history` (`history.ts`, `shadowIde.ts`): assert at the adapter boundary, not only in the builder, because an adapter that passes a field the builder ignores today would leak when the builder changes.
2. **No assistant prose.** The same for an assistant message marker.
3. **A verdict cannot come from data.** Already covered for the addressed-text case (`reviewerAddressedHandler.vitest.ts`); add a case where a tool argument contains a fake JSON verdict and the reply parser is fed a model reply that does not.
4. **Injection set aimed at the reviewer's own prompt:** extend the B4 set past the 16 cases (paraphrase, other languages, encoded or split payloads are the known bypasses recorded in `reviewer-isolation.md`); run with `--repeat 3` because the floor false-allow rate flips between identical runs at temperature 0. Cost belongs to the owner's spend approval (DR5 pending).
5. **Worker reviews** (waves): a review request built for a worker's call contains the worker's calls only (scenario `loop-reviewer-isolation`).

## 9. Recommended build order

### 9.1 Critical path

The dependencies that decide the order (everything else is independent):

1. **N0b** (CLI waves onto `core/util/worktree.ts`) unblocks N2 and N6 and N7 in the CLI, and is the precondition for a deterministic wave harness that uses real git.
2. **N6 Node default** unblocks **N5a** (a check in the worker's tree needs deps).
3. **N1** (measurement) prices N3 and N5b, so those two wait for it; N2 and N5a do not (they are safety, not tuning).
4. **#701** (settings dialog, in flight) is the home of the Y0 control, the wave switch and `waveUndeclared`; build the fields as soon as it merges, not before.
5. **Y4 before Y6** (a red baseline contaminates the experiment arms). **Y2 before Y3** (the handoff reads the dirty list). **Y1 and Y3 as one change.**

### 9.2 Quick wins (S, independent, no model)

1. Correct the ROADMAP (F7 built, F table state column, `.continuous/plans`, Y7 built, N0 and N6 CLI note): documentation only.
2. **Y4** baseline run of the fallback check.
3. **Y0 control** in #701's dialog.
4. **U4** isolation tests.
5. **U1 arm B**, with the minimum-size guard.
6. **N8b**: a test that diffs `passThrough.ts` against `MessageTypes.kt` (the real gap is 18, not 5) and a generated Kotlin list if the diff test is annoying to keep green.
7. **F2b step 1**: read-only Ctrl+T expand.
8. **Y2** clean-state note.

### 9.3 2.16.0 candidates (recommended, pending owner)

Selected for being safe, small and independent of the in-flight loop UI work: **Y4, Y0 control, Y2, Y1+Y3, U4, U1 arm B, N8b, F2b step 1, F5a, and the ROADMAP corrections**. Waves: **N0b, N2, N6 (Node default plus inbox surface)** as one "waves are safe in the CLI too" theme, in that order, **only if N1's scripted deterministic harness (section 6) lands with them**; otherwise 2.17.0. N5a joins when N6 is in. Sizes: Y4 S-M, Y0 S, Y2 S, Y1+Y3 M, U4 S, U1B S, N8b S, F2b-1 S, F5a M, N0b M, N2 M, N6 M, N5a M. That is roughly four S, three M-S and five M: a full release for one agent per track; N0b to N6 is the longest chain.

### 9.4 Later (2.17.0 or beyond)

N1 live measurement (needs model spend and the harness), N3, N5b, N9 (CLI needs a slot source), N7 (command and Settings action, after N0b), N12 (reserve), F7b (IDE plan notice), F2b step 2, Y5 shadow verifier, Y8, Y6 (paid experiments), T4 (budgets shared across workers) after N12.

### 9.5 Defer or drop, with reasons

| Row                                             | Call                   | Reason                                                                                                       |
| ----------------------------------------------- | ---------------------- | ------------------------------------------------------------------------------------------------------------ |
| F6                                              | Drop (mark superseded) | Loop items and waves already give a fresh context per unit; the rest is Track O                              |
| F5b                                             | Defer, default off     | A request per turn end; fights questions; Loop has the real gate                                             |
| N4                                              | Defer until N1         | Measure refused-call cost first; check grant inheritance (4.5)                                               |
| N10                                             | Defer                  | Anthropic's agent teams are experimental and Cognition argues against shared channels; no evidence in coding |
| Y5 (gating)                                     | Defer; shadow only     | A model call per item; measure agreement before it gates                                                     |
| U1 full, U2, U3, U5                             | Stay parked            | Gain small by the plan's own estimate; thread loses on isolation                                             |
| Best of N for loop items (loop-mode proposal 9) | Defer                  | N times the tokens; belongs to Track O's A6                                                                  |

## 10. Open questions for the owner

Recommended defaults are marked (recommended, pending owner).

1. **Scope of 2.16.0 for waves.** Ship N0b, N2, N6 and N5a together, with the deterministic harness, or only the harness and N0b? (recommended, pending owner: all four with the harness; if the harness slips, ship N0b alone.)
2. **Undeclared files.** `allow-disjoint` as default, `refuse` as the strict option? (recommended, pending owner: `allow-disjoint`, with lockfiles and build output stripped.)
3. **Node worktrees.** Link `node_modules` by default, accepting that an install in a worker writes through the link, or require `worktrees.json`? (recommended, pending owner: link, only when a lockfile exists, with the prompt line forbidding installs and an inbox note.)
4. **Y4 policy.** When the baseline fails, block the start with three actions, or warn and start? (recommended, pending owner: block, because three failures stop the loop anyway.)
5. **Progress file name and place.** `.continuous/plans/<slug>.<loop id>.progress.md` beside the plan, append-only, host-written, scrubbed? (recommended, pending owner: yes; confirm that the project-folder lock leaves `plans/` writable by the host.)
6. **F6.** Mark superseded? (recommended, pending owner: yes.)
7. **F5a wording and entry points.** "Continue in a new session" on the cold-cache notice, the plan card and after compaction? (recommended, pending owner: all three, plan card first.)
8. **Thresholds for N3 and N5b** (build if refusals or re-done work exceed 10% of a wave's tokens) and for default-on waves (25% faster at no more than 1.3x tokens). (recommended, pending owner: these numbers, labelled proposed.)
9. **Reviewer shown the item goal?** (recommended, pending owner: no, revisit with shadow-mode data.)
10. **Paid runs.** N1 and Y6 need model spend; U4's injection extension needs DR5's spend approval. Approve a bounded budget for N1 first? (recommended, pending owner: yes, one local-model run on Strata, free, then one cheap Bedrock row.)
11. **IntelliJ.** Accept a diff test (N8b) as the fix instead of a generated list? (recommended, pending owner: test first.)
12. **CLI Ctrl+T.** Accept it as the expand key if a grep of existing handlers shows no clash? (recommended, pending owner: yes.)

## 11. Proposed ROADMAP changes (exact text)

These replace or add to rows of `plans/ROADMAP.md`. Table cells keep the file's column order. Nothing below has been applied.

### 11.1 Track F

Add a State column and replace the table body:

```
| PR | Scope | Depends on | State |
| -- | ----- | ---------- | ----- |
| F0 | Measure where the list should sit in the request, using the live Bedrock cache test; confirm a free CLI key | none | Built, replaced: a deterministic test (`Bedrock.test.ts`, `Bedrock.taskList.vitest.ts`) settled the position; a live Bedrock run is optional |
| F1 | `TaskPlan` in core and on `Session`; `TaskList` tool with a `Checklist` alias; the list in each request; summary prompts | F0 | Built |
| F2 | CLI progress strip, expand key, keyboard editing | F1 | Partly: the strip is built (`TaskProgressStrip.tsx`); the expand key and keyboard editing are not. Split into F2a (read-only expand with Ctrl+T, S) and F2b (keyboard editing, M); from `research/area-loop-planning-waves-reliability.md` |
| F3 | IDE: tool, session field, list under the input, in-place editing | F1 | Built |
| F4 | Plan files in `.continuous/plans/` (the code's `PLANS_DIR`), seeding the list | F1 | Built |
| F5 | New session with this plan: "Continue in a new session" on the cold-cache notice, the plan card (Build in a new session) and after compaction, sharing one seed function with `continuous plan build` (M); the optional block-completion setting is split off as F5b and deferred (default off) | F1, C6 | Not started (F5a: 2.16.0 candidate) |
| F6 | Subtasks with their own conversation | F1, E1 | Superseded by Loop items and waves (a fresh context per item) and by Track O; not scheduled |
| F7 | Plan resume from disk: `cn plan list` and `cn plan build <file>`, and a start-up notice when the workspace has a plan file with open steps and no list is loaded | F4 | Built for the CLI 2026-11-11 (`commands/plan.ts`, `plans/planStore.ts`, `docs/ide-extensions/agent/plan-files.mdx`); the IDE start-up notice is F7b (S, not started) |
```

### 11.2 Track N

Replace N0, N6 and N7 and add N0b, N11, N12, N13:

```
| N0 | ... (keep scope) | #371 | Built in part: ... as before. Update 2026-11-12: the CLI wave still creates worktrees with `cn review`'s helper (`commands/review/worktree.ts`) and applies patches with a bare `git apply`; see N0b |
| N0b | CLI waves onto the core worktree service: `loopWave.ts` calls `createItemWorktree`, `applyPatch` (with `touchedSince`), `removeWorktree` from `core/util/worktree.ts` with `execFileGit`, so the CLI gets `continued/loop-*` branches, setup commands behind trust, the baseline commit and stale-worktree removal; test a `cn` start in a repository subdirectory | N0 | Not started (M); from `research/area-loop-planning-waves-reliability.md` |
| N2 | Undeclared files: compare `patchFiles(patch)` with the item's `files:` through the overlap helper; setting `waveUndeclared` = `allow-disjoint` (default: accept when no undeclared file is in another running or merged item's files, the person's dirty files or this wave's merged files, and say so in the inbox), `refuse` or `off`; lockfiles and build output are stripped from the patch before the check | N0b | Not started (M) |
| N5 | A worker's own `check:` runs in its worktree before the merge (N5a), so a failing item never reaches the checkout, and the check runs again in the checkout when another item merged first; a refused patch gets one retry with `git apply --3way` on a scratch worktree, opt-in and after N3 (N5b) | N6, N1 (N5b) | Not started (N5a M, N5b M) |
| N6 | ... (keep scope) | #373 | Built in part ... as before. Update 2026-11-12: the CLI never runs setup commands (N0b); the Node default links `node_modules` only when a lockfile exists, tells the worker not to install packages and shows "Worktrees share your node_modules" in the inbox |
| N7 | Leftovers: a command and a Settings action that list and remove `continued/loop-*` worktrees and branches, and the CLI's `cn-review-*` directories until N0b; on `cn serve` start remove loop worktrees whose loop no longer exists; the inbox shows a finished wave's merged files once | N0b | Partly: `listLoopWorktrees` exists, its only caller is the stale-removal before a new worktree for the same item |
| N8 | JetBrains: the `PASS_THROUGH_TO_CORE` list in `MessageTypes.kt` differs from `core/protocol/passThrough.ts` by 18 types (measured 2026-11-12: `subagents/list`, `models/serverConcurrency`, `models/detectLocal`, `models/catalog`, `config/setModelRoles`, `policy/load`, `policy/save`, six `audit/*`, `model/retirementNotice`, `model/dismissRetirementNotice`, `config/convertConnectionToAccount`, `openaiCompat/probeStatus`, `openaiCompat/testConnection`); first a test that diffs the two lists (N8b, S), then the missing entries | none | Not started |
| N11 | Wave scenarios in the deterministic harness: `bench/scenarios/loop-wave-*.json` with a real temporary git repository and the real worktree service (disjoint, undeclared, refused merge, check fails in the worktree, killed worker), run in CI | N0b | Not started (M) |
| N12 | Budget reservation: before a wave starts, sum the chosen items' shares (`loopBudgetSplit.ts`) and shrink the wave to what the remaining loop budget covers, saying why; show a worker's tokens on its row even when its changes were not merged | N1 | Not started (S) |
| N13 | Grants carry into workers: check whether a CLI worker receives the grants of earlier inline runs (`loopGrantKey`); if not, pass them; measure refused calls before N4 | N1 | Not started (S) |
```

N1 gains: "Scenarios and the decision rule are in `research/area-loop-planning-waves-reliability.md` section 4.6 (build N3 and N5b if refusals or re-done work exceed 10% of a wave's tokens; N4 if one item in five fails on a refused call; waves default-on only if 25% faster at no more than 1.3x the tokens; thresholds proposed)."

N3 gains: "Park the patch in `<git dir>/continued/parked/` (scrubbed, outside `git status`), record `LoopItemState.parkedPatch`, and apply it to the item's next worktree with `git apply --check` first."

### 11.3 Track Y

```
| Y0 | ... | none | Built, off by default (#486) ...; the settings control ("Check every item with") belongs in #701's dialog and the plan card (S) |
| Y1 | A progress file the harness writes: append-only `.continuous/plans/<slug>.<loop id>.progress.md`, one block per run (status, attempts, check command and the last 20 lines of its output, changed files, the model's report, notes, next); the next item's first message names it; never read back into decisions; scrubbed; capped | none | Not started (M, with Y3) |
| Y2 | A clean-state note at item end: `LoopItemState.dirty` (capped at 20 paths) from `git status --porcelain` (IDE: `loop/dirtyFiles`), shown for the next item and on the row; setting `loopMode.cleanState`, off by default; informs, never blocks | none | Not started (S) |
| Y4 | A baseline run of the fallback check at loop start: `LoopState.fallbackBaseline`; a failing or refused baseline stops the start with three actions (start without a fallback, edit the command, start anyway: advisory only); `cn serve` reports it in `/state` | Y0 | Not started (S to M); the smallest fix for "every item fails its check" |
| Y5 | Split: goal-level done criteria (plan-file change, needs the owner) and a shadow verifier for items with no runnable check (records its verdict beside the harness's; gates nothing until agreement is measured on the bench loop scenarios) | Y0 | Not started |
| Y7 | ... | Y-track | Built: tests #539 and the product fix #551 (merged 2026-11-11) |
```

### 11.4 Track U

```
| U1 | Narrowed to arm B: a cache hint on the reviewer's system prompt only, only when the model's family supports it, the prompt clears the model's minimum (`packages/llm-info/src/promptCache.ts`) and the model entry's own `promptCaching` is unset; no reorder, no new UI; unit tests on request building | U0 | Not started (S); ship behind the existing setting; stop unless a bench run shows reviews above 5% of a run's cost |
| U4 | Isolation tests: no tool output and no assistant prose in a review request, asserted at the CLI and IDE adapter boundaries as well as in `buildReviewMessages`; a fake verdict in a tool argument is not a verdict; a worker's review carries only the worker's calls; the B4 injection set extended past 16 cases with `--repeat 3` (spend: DR5) | none | Not started (S offline, the extension waits for spend approval) |
```

### 11.5 Next 20 and the critical path

Add to the list of deferred items: "N4 until N1; N5b until N1 and N3; F5b and F6 (superseded); Y5 gating until a shadow verifier is measured." Add a sentence under Track N's problem paragraph: "The CLI wave does not use the core worktree service yet (N0b); the safety rows N2, N5a and N6 depend on it."

### 11.6 Suggested wording, for the loop UI

New user-facing strings proposed for the in-flight loop UI (#697 status line, #700 tray, #701 dialog); nothing here changes those pull requests:

- Status line: "Waves off: the model server has one slot" (N9).
- Item row: "Ran in parallel, 41k tokens, changes not merged" and "Kept its work for the next run" (N3); "Changed files it did not declare: `x.ts`" (N2).
- Plan card, before start: "The check `npm test` already fails before any item runs." with "Start without a fallback", "Edit the command", "Start anyway" (Y4).
- Settings dialog: "Check every item with" (Y0); "Files a parallel item changes without declaring them: Accept if nothing else uses them / Refuse" (N2).
- Session action: "Continue in a new session: starts empty and keeps your task list and plan file" (F5a).

## 12. Sources

Internal: `plans/task-planning.md`, `plans/parallel-agents.md`, `plans/loop-mode.md` (sections "Next: parallel items as subagents", "Parallel waves (run 7)"), `plans/loop-reliability.md`, `plans/reviewer-isolation.md`, `plans/reviewer-audit.md`, `plans/reviewer-eval-gate.md`, `plans/loop-budgets.md`, `plans/research/loop-refusal-detection.md` (not repeated), `plans/ROADMAP.md` at `028a740`. Code citations are inline.

External (fetched 2026-11-12 unless marked): https://code.claude.com/docs/en/sub-agents; https://code.claude.com/docs/en/agent-teams; https://www.anthropic.com/engineering/multi-agent-research-system; https://cognition.com/blog/dont-build-multi-agents; https://docs.cline.bot/features/subagents; https://cursor.com/docs/cloud-agent; https://aider.chat/docs/usage/lint-test.html. Search-only (**UNVERIFIED** in detail): https://docs.openhands.dev/sdk/guides/agent-stuck-detector; https://arxiv.org/pdf/2503.13657.pdf; arXiv 2607.04697 through https://www.alphaxiv.org/abs/2607.04697.md and https://agentpatterns.ai/workflows/concurrent-agent-pr-merge-conflicts/; https://verdent.ai/guides/codex-app-first-impressions-2026. Carried from earlier notes with their own dates: https://www.anthropic.com/engineering/effective-harnesses-for-long-running-agents; https://www.anthropic.com/engineering/harness-design-long-running-apps; https://developers.openai.com/blog/run-long-horizon-tasks-with-codex.md; https://www.anthropic.com/engineering/claude-code-auto-mode; https://learn.chatgpt.com/docs/sandboxing/auto-review.md.
