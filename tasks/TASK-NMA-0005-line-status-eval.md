# TASK-NMA-0005 — Line Status Eval

<!-- continuity:task {"acceptance":["tsx scripts/eval-line-status.ts prints train and held-out clean rates per check over replayed cases","checks.test.ts passes offline, including the wrong A train reply from #627","docs/eval/line-status holds the loop and a handoff DeepSeek can run alone","no real rider questions are collected"],"depends_on":[],"goal":"Line status answers are scored on many replayed cases so each change to the chat is kept or dropped on numbers.","id":"NMA-0005","issue_url":"https://github.com/Pukujan-lab/nyc-map-agent/issues/629","next_action":"run iteration 3: take a fresh baseline on the fixed runner (a dropped connection no longer becomes an empty reply), then change one prompt line at a time; iteration 2, which dropped the shuttle bus from the prompt, measured worse on held-out and is recorded as rejected in LEDGER.md","owner":"claude-code","priority":"P2","protocol_version":"0.1.0-draft","schema":"project-continuity.task.v1","status":"active","why":"One wrong A train answer was fixed by hand and nothing measures how often the chat misreads line status (#629)."} -->

- Status: active
- Owner: claude-code
- Priority: P2
- Depends on: none

## Goal

Line status answers are scored on many replayed cases so each change to the chat is kept or dropped on numbers.

## Why

One wrong A train answer was fixed by hand and nothing measures how often the chat misreads line status (#629).

## Allowed files

- `scripts/eval/line-status/`, `scripts/eval-line-status*.ts`, `scripts/record-alert-snapshot.ts`, `docs/eval/line-status/`, `.gitignore`, `checkpoints/`, this file.

## Human outcome

Every change to how the chat retells MTA trouble is judged on numbers from many replays, and a cheaper model can run that loop for hours.

## Scope and boundaries

- In scope: line status questions; the harness, recorder, generator and docs.
- Out of scope: trip questions (next suite), training LFM3, collecting real rider questions.
- Dependencies/uncertainty: LFM3 on the MacBook Pro must be awake; DeepSeek's key is not set up yet.

## Acceptance criteria

- [ ] The runner reports clean rates for train and held-out cases.
- [ ] Offline tests pass.
- [ ] The handoff and loop are in docs/eval/line-status.

## Evidence and sources

A 12-trial smoke run on LFM3 (prompt as merged in #628) came back 3 of 12 clean: 9 replies ended with an unwanted "Want to start?", and several invented a C shuttle bus. `npx vitest run scripts/eval` passes (10 tests), `tsc`, `eslint` and `depcruise` are clean. The full baseline is in docs/eval/line-status/LEDGER.md.

## Reproduction details (only when needed)

Starting revision, material inputs/configuration, runtime, exact command or prompt, observed result, and limitations.

## Related records

- Required leaf owning issue, parent ancestry and dependencies (or explicitly none): #629; related #627, #628; no parent.
- Primary writer / branch / source issue revision / as-of status:
- Related PR/CI evidence and push receipt (request ID / SHA):

## Checkpoint log

No checkpoints yet.

### 2026-11-01 10:12:09 UTC — claude-code

<!-- continuity:checkpoint {"agent":"claude-code","blocked":["none"],"changed":["scripts/eval-line-status*.ts, scripts/record-alert-snapshot.ts, scripts/eval/line-status/, docs/eval/line-status/, .gitignore, checkpoints/CURRENT.md"],"completed":["Built the line status eval: runner, ten rule checks, cases, recorder, DeepSeek generator, soak loop, handoff; opened #630 with auto-merge"],"decisions":["no new decisions"],"evidence":["npx vitest run scripts/eval: 10 passed; tsc, eslint, depcruise clean; 12-trial smoke run on LFM3 was 3 of 12 clean"],"evidence_class":"observed","next_action":"when the full baseline finishes, add its row to docs/eval/line-status/LEDGER.md in a follow-up pull request; DeepSeek key still to be set; PRIVACY.md change before any real questions","protocol_version":"0.1.0-draft","schema":"project-continuity.checkpoint.v1","task_id":"NMA-0005","timestamp":"2026-11-01T10:12:09Z"} -->
<!-- continuity:checkpoint-operation {"payload_sha256":"c8a34dcc77ff4033d2d68922eaa7db648438c0c0e3c5d4101bd8a014d96335c0","request_id":"566053ccd68a418c9c438d54e8ab6048","schema":"project-continuity.checkpoint-operation.v1","task_id":"NMA-0005"} -->

Completed:
- Built the line status eval: runner, ten rule checks, cases, recorder, DeepSeek generator, soak loop, handoff; opened #630 with auto-merge

Evidence:
- npx vitest run scripts/eval: 10 passed; tsc, eslint, depcruise clean; 12-trial smoke run on LFM3 was 3 of 12 clean

Decisions:
- no new decisions

Changed:
- scripts/eval-line-status*.ts, scripts/record-alert-snapshot.ts, scripts/eval/line-status/, docs/eval/line-status/, .gitignore, checkpoints/CURRENT.md

Blocked/uncertain:
- none

Next:
- when the full baseline finishes, add its row to docs/eval/line-status/LEDGER.md in a follow-up pull request; DeepSeek key still to be set; PRIVACY.md change before any real questions

### 2026-11-01 10:22:35 UTC — claude-code

<!-- continuity:checkpoint {"agent":"claude-code","blocked":["none"],"changed":["docs/eval/line-status/LEDGER.md"],"completed":["Recorded the LFM3 baseline in the ledger: 31 of 174 trials clean; opened #631 with auto-merge"],"decisions":["no new decisions"],"evidence":["Run baseline-after-628, 58 cases x 3 trials, commit b17e6ce7f88a: train 14.6%, held-out 25.5%"],"evidence_class":"observed","next_action":"DeepSeek runs the loop in docs/eval/line-status/PROGRAM.md starting with the unwanted Want to start? and the invented shuttle; owner sets DEEPSEEK_API_KEY and approves the PRIVACY.md change","protocol_version":"0.1.0-draft","schema":"project-continuity.checkpoint.v1","task_id":"NMA-0005","timestamp":"2026-11-01T10:22:35Z"} -->
<!-- continuity:checkpoint-operation {"payload_sha256":"4bbfae36ac7054bd2025c029564c5c143a3900f0426876d4e73b5bf58b618f35","request_id":"20bef696ab7641999b24a95321885c52","schema":"project-continuity.checkpoint-operation.v1","task_id":"NMA-0005"} -->

Completed:
- Recorded the LFM3 baseline in the ledger: 31 of 174 trials clean; opened #631 with auto-merge

Evidence:
- Run baseline-after-628, 58 cases x 3 trials, commit b17e6ce7f88a: train 14.6%, held-out 25.5%

Decisions:
- no new decisions

Changed:
- docs/eval/line-status/LEDGER.md

Blocked/uncertain:
- none

Next:
- DeepSeek runs the loop in docs/eval/line-status/PROGRAM.md starting with the unwanted Want to start? and the invented shuttle; owner sets DEEPSEEK_API_KEY and approves the PRIVACY.md change

### 2026-11-01 10:23:06 UTC — claude-code

<!-- continuity:checkpoint {"agent":"claude-code","blocked":["none"],"changed":[".coord/boss_claim.json"],"completed":["Committed the boss seat change another agent (workbuddy@air) made to .coord/boss_claim.json"],"decisions":["no new decisions"],"evidence":["git diff showed only the seat handover at 2026-11-01T10:21:23Z; seat_protocol status OK"],"evidence_class":"observed","next_action":"DeepSeek runs the loop in docs/eval/line-status/PROGRAM.md; owner sets DEEPSEEK_API_KEY and approves the PRIVACY.md change","protocol_version":"0.1.0-draft","schema":"project-continuity.checkpoint.v1","task_id":"NMA-0005","timestamp":"2026-11-01T10:23:06Z"} -->
<!-- continuity:checkpoint-operation {"payload_sha256":"0075dca6d17fe0368f1e4abc2d2d3d9ef78c7849fb05ae0635445b93216ea4f6","request_id":"da6900253b6f4c31b4ce708aced39d0e","schema":"project-continuity.checkpoint-operation.v1","task_id":"NMA-0005"} -->

Completed:
- Committed the boss seat change another agent (workbuddy@air) made to .coord/boss_claim.json

Evidence:
- git diff showed only the seat handover at 2026-11-01T10:21:23Z; seat_protocol status OK

Decisions:
- no new decisions

Changed:
- .coord/boss_claim.json

Blocked/uncertain:
- none

Next:
- DeepSeek runs the loop in docs/eval/line-status/PROGRAM.md; owner sets DEEPSEEK_API_KEY and approves the PRIVACY.md change

### 2026-11-01 10:49:18 UTC — workbuddy

<!-- continuity:checkpoint {"agent":"workbuddy","blocked":["none"],"changed":["server/features/agent/routes.ts, ask.test.ts, docs/eval/line-status/LEDGER.md, checkpoints/CURRENT.md"],"completed":["Dropped the model's own Want to start? when no trip set a follow-up; the eval moved train trials clean from 14.6% to 43.9% and held-out from 25.5% to 39.2%; opened #632"],"decisions":["The unwanted offer was the app letting the model's close through, not the prompt, so the fix belongs in routes.ts"],"evidence":["npx vitest run server/features/agent: 298 passed; tsc and eslint clean; eval-line-status-compare printed keep over 174 trials per run on LFM3"],"evidence_class":"observed","next_action":"iteration 2 on the 5 remaining offer trials: the route holds one exact sentence, so widen what it holds back","protocol_version":"0.1.0-draft","schema":"project-continuity.checkpoint.v1","task_id":"NMA-0005","timestamp":"2026-11-01T10:49:18Z"} -->
<!-- continuity:checkpoint-operation {"payload_sha256":"df128786f8af48d5886b8dcef876ae8d6660a7addab9498253aa7a10cc1b0f3c","request_id":"d69b027154794a2ca4d9c3579194714c","schema":"project-continuity.checkpoint-operation.v1","task_id":"NMA-0005"} -->

Completed:
- Dropped the model's own Want to start? when no trip set a follow-up; the eval moved train trials clean from 14.6% to 43.9% and held-out from 25.5% to 39.2%; opened #632

Evidence:
- npx vitest run server/features/agent: 298 passed; tsc and eslint clean; eval-line-status-compare printed keep over 174 trials per run on LFM3

Decisions:
- The unwanted offer was the app letting the model's close through, not the prompt, so the fix belongs in routes.ts

Changed:
- server/features/agent/routes.ts, ask.test.ts, docs/eval/line-status/LEDGER.md, checkpoints/CURRENT.md

Blocked/uncertain:
- none

Next:
- iteration 2 on the 5 remaining offer trials: the route holds one exact sentence, so widen what it holds back

### 2026-11-01 11:15:51 UTC — claude-code

<!-- continuity:checkpoint {"agent":"claude-code","blocked":["none"],"changed":[".codebuddy/settings.json"],"completed":["Committed the workbuddy agent's leftover hook-timeout edit to .codebuddy/settings.json in #633 with auto-merge"],"decisions":["no new decisions"],"evidence":["git diff showed only timeouts and a no-prompt env prefix on the hook commands"],"evidence_class":"observed","next_action":"remove Groq from the speech-to-text endpoint as the owner asked","protocol_version":"0.1.0-draft","schema":"project-continuity.checkpoint.v1","task_id":"NMA-0005","timestamp":"2026-11-01T11:15:51Z"} -->
<!-- continuity:checkpoint-operation {"payload_sha256":"c5c12e640680b9379644ec2c78e141451d6df10b1747ec87741dd0fbc8d0fc50","request_id":"39cd4d17465240e0982eb1c33f58b2d3","schema":"project-continuity.checkpoint-operation.v1","task_id":"NMA-0005"} -->

Completed:
- Committed the workbuddy agent's leftover hook-timeout edit to .codebuddy/settings.json in #633 with auto-merge

Evidence:
- git diff showed only timeouts and a no-prompt env prefix on the hook commands

Decisions:
- no new decisions

Changed:
- .codebuddy/settings.json

Blocked/uncertain:
- none

Next:
- remove Groq from the speech-to-text endpoint as the owner asked

### 2026-11-01 11:47:05 UTC — dsh (the model deepseek-v4.1-flash)

<!-- continuity:checkpoint {"agent":"dsh (the model deepseek-v4.1-flash)","blocked":[],"changed":["tasks/TASK-NMA-0001..0006, checkpoints/CURRENT.md, docs/PRIVACY.md"],"completed":["The records agree with GitHub again: five PCM tasks (#614, #618, #625, #627, #634) now say completed instead of active, and CURRENT.md lists only the two pull requests that are really open"],"decisions":["Leave NMA-0005 as the one active task, because #629 is still open and iteration 2 is unstarted"],"evidence":["gh issue view on all five issues shows CLOSED on 2026-11-01; gh pr list shows only #378 and #232 open; continuity validate prints VALID"],"evidence_class":"observed","next_action":"Run iteration 2 of the line status loop per docs/eval/line-status/PROGRAM.md: widen what server/features/agent/routes.ts withholds so the five trials that still close with a trip offer pass, and record the result in LEDGER.md","protocol_version":"0.1.0-draft","schema":"project-continuity.checkpoint.v1","task_id":"NMA-0005","timestamp":"2026-11-01T11:47:05Z"} -->
<!-- continuity:checkpoint-operation {"payload_sha256":"4e42a2894eeec6143888a06ead863bf9d31b36df581a6039dd046428c5455d7e","request_id":"a23598e2562b4fa59e5550c9e63c6c1d","schema":"project-continuity.checkpoint-operation.v1","task_id":"NMA-0005"} -->

Completed:
- The records agree with GitHub again: five PCM tasks (#614, #618, #625, #627, #634) now say completed instead of active, and CURRENT.md lists only the two pull requests that are really open

Evidence:
- gh issue view on all five issues shows CLOSED on 2026-11-01; gh pr list shows only #378 and #232 open; continuity validate prints VALID

Decisions:
- Leave NMA-0005 as the one active task, because #629 is still open and iteration 2 is unstarted

Changed:
- tasks/TASK-NMA-0001..0006, checkpoints/CURRENT.md, docs/PRIVACY.md

Blocked/uncertain:
- none

Next:
- Run iteration 2 of the line status loop per docs/eval/line-status/PROGRAM.md: widen what server/features/agent/routes.ts withholds so the five trials that still close with a trip offer pass, and record the result in LEDGER.md

### 2026-11-01 17:34:46 UTC — dsh (the model deepseek-v4.1-flash)

<!-- continuity:checkpoint {"agent":"dsh (the model deepseek-v4.1-flash)","blocked":[],"changed":["scripts/eval-line-status.ts, scripts/eval/line-status/retry.ts, retry.test.ts, docs/eval/line-status/LEDGER.md, docs/eval/line-status/PROGRAM.md, checkpoints/CURRENT.md"],"completed":["Ran the loop's baseline and one iteration on LFM3, and fixed the harness flaw those runs exposed: a dropped connection was scored as an empty reply, so the eval counted the network against the model"],"decisions":["Reject the shuttle prompt change: held-out fell 25 points and denies-trouble rose from 3 trials to 28, which is fitting the cases rather than fixing the reading"],"evidence":["baseline 45.4% train and 49.0% held-out; the shuttle prompt change 73.0% train and 23.5% held-out, which the comparer called reject, so it was dropped; 15 eval tests pass, tsc and eslint clean, and with the tunnel down the runner now exits 1 instead of writing empty-reply rows; #642 merged"],"evidence_class":"observed","next_action":"Run iteration 3: take a fresh baseline on the fixed runner, then change one prompt line at a time; do not rerun the shuttle wording","protocol_version":"0.1.0-draft","schema":"project-continuity.checkpoint.v1","task_id":"NMA-0005","timestamp":"2026-11-01T17:34:46Z"} -->
<!-- continuity:checkpoint-operation {"payload_sha256":"19fb0f2a19293ef514264e9fee83c54b555654f0626831296460826baad45269","request_id":"c2f99253a9a34efd826210f16796d8c2","schema":"project-continuity.checkpoint-operation.v1","task_id":"NMA-0005"} -->

Completed:
- Ran the loop's baseline and one iteration on LFM3, and fixed the harness flaw those runs exposed: a dropped connection was scored as an empty reply, so the eval counted the network against the model

Evidence:
- baseline 45.4% train and 49.0% held-out; the shuttle prompt change 73.0% train and 23.5% held-out, which the comparer called reject, so it was dropped; 15 eval tests pass, tsc and eslint clean, and with the tunnel down the runner now exits 1 instead of writing empty-reply rows; #642 merged

Decisions:
- Reject the shuttle prompt change: held-out fell 25 points and denies-trouble rose from 3 trials to 28, which is fitting the cases rather than fixing the reading

Changed:
- scripts/eval-line-status.ts, scripts/eval/line-status/retry.ts, retry.test.ts, docs/eval/line-status/LEDGER.md, docs/eval/line-status/PROGRAM.md, checkpoints/CURRENT.md

Blocked/uncertain:
- none

Next:
- Run iteration 3: take a fresh baseline on the fixed runner, then change one prompt line at a time; do not rerun the shuttle wording

### 2026-11-01 17:39:25 UTC — dsh (the model deepseek-v4.1-flash)

<!-- continuity:checkpoint {"agent":"dsh (the model deepseek-v4.1-flash)","blocked":[],"changed":["tasks/TASK-NMA-0005-line-status-eval.md"],"completed":["Pointed the task record at iteration 3 on the fixed runner, so a new session does not repeat the shuttle change that already measured worse on held-out"],"decisions":["Keep NMA-0005 active: #629 is still open and no iteration has been accepted yet"],"evidence":["the record's next action names the fresh baseline and one-prompt-line-at-a-time rule; continuity validate reports VALID for the record's shape; the change is in #646"],"evidence_class":"observed","next_action":"Merge #646, then take the iteration 3 baseline on the fixed runner; do not rerun the shuttle wording","protocol_version":"0.1.0-draft","schema":"project-continuity.checkpoint.v1","task_id":"NMA-0005","timestamp":"2026-11-01T17:39:25Z"} -->
<!-- continuity:checkpoint-operation {"payload_sha256":"d213697c4aa1515fdd0478b4fbba1368415322e0eb570bccbc7055a55a509431","request_id":"830eb576eeae4b038163a7fdd975e76b","schema":"project-continuity.checkpoint-operation.v1","task_id":"NMA-0005"} -->

Completed:
- Pointed the task record at iteration 3 on the fixed runner, so a new session does not repeat the shuttle change that already measured worse on held-out

Evidence:
- the record's next action names the fresh baseline and one-prompt-line-at-a-time rule; continuity validate reports VALID for the record's shape; the change is in #646

Decisions:
- Keep NMA-0005 active: #629 is still open and no iteration has been accepted yet

Changed:
- tasks/TASK-NMA-0005-line-status-eval.md

Blocked/uncertain:
- none

Next:
- Merge #646, then take the iteration 3 baseline on the fixed runner; do not rerun the shuttle wording

## Handoff

Read PROJECT → CURRENT → this task → minimum relevant spec. Checkpoint before stopping.
