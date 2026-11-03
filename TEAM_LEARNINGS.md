# Shared working notes

Last updated: 2026-11-03. Read this before starting work; update it when an
experiment changes what we know. This is a shared operating record for both
developers and their agents, not a competition submission document.

## Agreed workflow

- Commit and push completed work to this fork. Do not open a competition PR
  until the user explicitly asks. The user explicitly authorized media upload
  and the die-task PR on 2026-11-03. Future tasks still need explicit submission
  authorization. Keep each submission branch limited to its task folder.
- `submission/roll-a-die` was submitted from the fork to upstream `main` as
  [PR #44](https://github.com/robocurve/benchmark-tasks/pull/44), commit `ba4ac81`.
  Its diff contains only `tasks/roll-a-die/`. Keep the submitted task unchanged
  while waiting for review; do not synchronize later working edits into it.
  Record follow-up notes on `roll-a-die`, outside the submission branch.
- The user confirmed upload team `T-39`. The private `.env.robocurve` stores
  `ROBOCURVE_TEAM` and a single-quoted `ROBOCURVE_TOKEN`. Parse the quoted value
  without displaying it; do not mistake empty quotes for a configured token.
- Before eventual submission, rescore the final demo/Dream evidence with the
  final scorer. This is complete for the final marked v3 demo/Dream evidence. Fresh
  GPU repeats are an additional confidence check, not an explicit competition
  requirement after a scorer-only change. Earlier notes incorrectly elevated
  them into a mandatory gate; do not repeat that interpretation.
- Reuse **one Brev VM**, currently `robocurve-dice`, while working daily.
  Prepare several tasks locally and batch their GPU trials in one session.
  Initially run simulator trials consecutively, rather than starting competing
  simulator processes on the same GPU.
- Before using the shared VM, check its live state and coordinate with the other
  developer. Record the operator, task/branch, intended runs and completion in a
  dated session entry here. Git notes are not a lock or a live status service;
  do not stop a VM while someone else's trial is running.
- Do scene design, scoring tests, trajectory analysis and documentation locally
  where possible. Start the GPU when a batch is ready. Download results, push
  code and confirm the VM reaches `STOPPED` when the session is finished.
- The user permits the **Dream API key on the team VM** when useful. Transfer it
  without displaying its contents; restrict file access and keep it outside Git,
  logs and artifacts. This approval does not require another confirmation next
  session. Direct Dream access should remove the Mac/SSH bridge dependency;
  direct execution is now verified. The key was transferred on November 3
  into an owner-only credentials file outside Git and logs. The final direct
  Dream run used one session with no retries; scene/rendering also changed, so
  its timing is not an isolated transport speed comparison.
- Keep the five private reference/application PDFs, credentials, `.env*`,
  generated media and full trial artifact directories ignored. Curated anonymous
  numeric traces may be committed inside a task as review evidence after a
  content check; the die task includes five such compressed traces (two current
  v3 runs and three historical runs). See
  [.gitignore](.gitignore).
  This repository is public: do not add account tokens or private application
  content to this log. Keep task text and submitted media anonymous.

## GPU cost and persistence

Observed on 2026-11-03: L40S, 48 GB VRAM, 256 GiB allocated disk. Running rate
**$3.28/hour**, comprising $3.23 compute and $0.05 storage. These are observed
rates for this instance, not guaranteed future prices.

| Quantity | Planning value | Meaning |
|---|---:|---|
| 10 minutes running | $0.55 | Elapsed instance time, including idle gaps; excludes separate Dream API charges. |
| $2 running budget | About 37 minutes | A target, not a user-imposed hard cap. |
| Storage while stopped | $1.20/day | The whole allocated disk, shared by all tasks on this VM; not per task. |
| Clean Dream trial | $0.18 | 197.996 seconds of measured runner wall time, prorated at $3.28/hour. |
| Initial cold installation | About 40 minutes | First environment installation/warmup; excluded from per-trial numbers. |

The actual build configuration is VM mode (`environment.build.vm`, with an
`on_create_script`). Legacy API flags such as `vmOnlyMode` were misleading.
According to [Brev's launchable documentation](https://docs.nvidia.com/brev/concepts/launchables),
the VM setup script does not automatically rerun on restart. The retained
installation should therefore be reusable; boot and simulator initialization
still recur. **Restart and installation reuse were verified later on November 3.**
The environment survived and the marked-die demos each took about 44 seconds
including simulator startup. Two earlier restart attempts at 13:08 and 13:11 UTC
failed because no GPU capacity was available in the existing region. Stopped data remained inaccessible; local
backups allowed scoring work to continue. Retaining a disk does not reserve a GPU.

Stopping ends compute charges but retains storage. Deleting ends the instance's
charges and removes its data and installation. Copying files locally does not
cancel the allocated disk. See [Brev lifecycle and persistence](https://docs.nvidia.com/brev/concepts/gpu-instances).
Keep the VM between daily sessions as agreed; reconsider retention for longer
gaps. Do not delete it as a routine cleanup step.

Code, final videos, setup images and measured trajectories are already local.
The original raw camera arrays and installed simulator remain on the VM. Before
any later deletion, identify and back up anything still needed. A fresh VM needs
setup again; restoring a full archived environment has not been tested.

Billing snapshot at 12:24 UTC on 2026-11-03: $196.95 of the initial $200 remained
($3.05 posted spend). Billing may lag. Creation through confirmed shutdown at the
displayed running rate gives a conservative **$4.43 estimate**, not an invoice.
Do not add overlapping per-run estimates to this total. Dream API dollars were
not reported by the SDK and remain unknown.

## What the first task taught us

The implementation and run commands are in
[tasks/roll-a-die/README.md](tasks/roll-a-die/README.md); the candid submission
assessment is [docs/roll-a-die-review.md](docs/roll-a-die-review.md).

| Finding | Evidence | Reusable lesson |
|---|---|---|
| Full gripper closure caused vibration around the 16 mm cube. | Trial 001: score 0. | Check contact behaviour visually; reachable poses alone do not prove a grasp. |
| A gentle 15 mm target jaw gap enabled stable pickup. | Trials 002 onward. | Tune grasp pressure/closure before adding a dynamic release. |
| Rotation about the jaw-closing axis transferred little tumble. | Trial 003: 30.274 degrees, score 0.25. | The wrist rotation axis relative to the grasp matters. |
| An upward stroke, world-X rotation and delayed opening produced a roll. | Trial 004: 164.434 degrees, score 1.0 in 9.30 simulated seconds. | Use measured release and object motion, not intended actions, as evidence. |
| A second simulator startup encountered a shader-cache miss. | Trial 004 wall time 321.206 s; earlier short trials 46–73 s. | Start serially initially; measure concurrency before assuming it saves money. |
| Per-tick remote bridge traffic caused Dream session expiry. | First Dream attempt: 49 attempts, 25 sessions, 24 expiries. | A completed evaluation can still be infrastructure-confounded. Inspect sessions and retries. |
| Batching observations fixed that transport problem. | Clean baseline: 25 requests, one session, zero retries; score 0.0. | Use the clean result, preserve the failed attempt as development evidence. |

The batched bridge preserves observation order, timestamps, states, prompt and
the model's frame window. Ten bridge tests, including real HTTP transport and
comparison with the Dream client, passed. The original version also passed twenty-two scorer tests.
Tests do not establish physical realism, repeatability or acceptance.

The runner records cube position, quaternion, linear/angular velocity and
measured hand state every **50 ms**; physics runs at 240 Hz. Scores can be
replayed from `trajectory.jsonl` without a GPU. Keep the final score, rather than
the best historical score, so later violations erase credit. Record source
snapshots, versions, seed, setup image, final videos and runtime for each trial.
Use a new artifact directory for every attempt; do not overwrite evidence.

The scene uses seed 0, no object jitter and a fixed scripted demonstration.
This establishes a simulated manipulation example, not a random/fair die or a
measured repeat-success rate. Numerical differences remain possible; exact
determinism has not been tested. V3 adds 1–6 pips for tracking faces; it still does not request a particular
result or measure outcome fairness.

## Current findings and next checks

- **V3 is current.** Six coloured pip-marked faces replace the blank cube.
  Pickup earns 0.25, visible release 0.5, and a post-release marked-face up→down
  sequence plus one second of rest earns 1.0. Exact thresholds are in the task.
  This replaces v2 acceleration/clearance predicates with pose/time checks.
- Final fresh recordings: `die-v3-demo-002` scores 1.0 after 182 actions / 9.10 s;
  `die-v3-dream-002` scores 0.0 after 1,200 actions / 60 s. All 48 tests pass. Both
  trajectories are independently rescored and committed anonymously with source
  hashes in `tasks/roll-a-die/VALIDATION.json`. Prior v2 evidence is historical.
- The review camera must be above the cube enough to see the upward face.
  A low oblique view hid cyan 5 in an otherwise passing run. The final raised
  camera shows cyan 5 up at 7.85 s and opposite red 2 up at 8.00 s, establishing
  cyan 5 down. Opposite-face evidence is valid because the marked cube is rigid
  and the face mapping is specified. Preserve the intervening frames.
- Readability needs real rendering checks, not just score telemetry. The final
  complete videos combine the 1600×1280 review view with all three policy views.
  The close-up is not a model input. Visual rulers do not add collision geometry;
  perspective prevents treating them as universal screen-space measurements.
- Direct Dream ran successfully on the VM: 25 requests / 25 attempts / 1 session.
  It returned 380 out-of-range prediction rows, including unused final-chunk rows.
  Standard execution bounds/step clamps are retained; all 1,200 executed actions
  pass bounds and step checks. Do not confuse returned predictions with executed
  actions, or evaluation status `success` with task success.
- The same frozen demo physics produced matching results twice, with only the
  review camera changed. This is not a statistical repeatability/fairness claim.
- Final media in `artifacts/roll-a-die-v3/` is uploaded as **M-PV3ZXY**:
  H.264/yuv420p, fast start, complete frame counts and below upload limits.
  The user's explicit upload-and-PR request supersedes the earlier approval
  blocker. Do not reuse the obsolete blank-cube videos.
- The refreshed live board had 128 entries (38 pending, 90 pilot) and the public
  repository had 43 prior PRs immediately before submission. No direct die-roll
  duplicate was found; this does not guarantee acceptance. The team token was
  accepted as T-39, and Robocurve received the `tommyet` PR as **TK-YBZD4Q**.

## Dated session log

### 2026-11-03 — final media upload and competition submission

- Operator: repository agent. User explicitly requested: "Media upload and PR.
  Submit as advised by doc." This authorizes this die-task submission.
- Uploaded the complete final v3 `dream.mp4`, `demo.mp4` and `setup.png` from
  `artifacts/roll-a-die-v3/` to Robocurve; returned media ID **M-PV3ZXY**.
  The token stayed in memory and out of command arguments/output/Git.
- The official Python uploader received Cloudflare 1010, including on a public
  unauthenticated page. Standard curl reached the same service successfully.
  Upload used curl with the official `/api/media` fields and authorization
  header passed privately through stdin. Do not repeat an upload after success.
- Independent final audit confirmed 21 task-only files, anonymous task text and
  evidence, matching core-source hashes and replay scores 1.0 / 0.0. No new
  GPU trial was necessary; the VM remained stopped.
- Opened non-draft [PR #44](https://github.com/robocurve/benchmark-tasks/pull/44)
  as `tommyet`, from `tommyet:submission/roll-a-die` to
  `robocurve/benchmark-tasks:main`, at 14:40:12 UTC. Submitted head `61268c3`;
  media and task docs were attached before creating the PR. The initial
  ingestion reported two field-length violations, corrected at `ba4ac81`
  before Robocurve received the task; simulation, scoring and media were unchanged.
- The GitHub connector could read the upstream repository but its PR-create
  call returned "Resource not accessible by integration". The existing
  authenticated `gh` CLI account successfully created the same requested PR.
- [Robocurve receipt](https://github.com/robocurve/benchmark-tasks/pull/44#issuecomment-6606759429)
  at **14:41:54 UTC**: received as **TK-YBZD4Q**, **waiting for review**.
  Final submitted commit **ba4ac81**, media **M-PV3ZXY**. Do not merge the PR
  ourselves. Acceptance is an upstream merge after organizer review.
- Newly verified text limits: `fidelity` maximum **500 characters**, `scores`
  maximum **300 characters**. Final fields are 406 / 275 characters; retain
  fuller explanations in README/JUDGING/VALIDATION. The ingestion bot accepts
  a correction pushed to the same PR before receipt, as it did here.
- The live program limits also report 20 submissions/day, 50 MB/video, 25 MB
  code and 95 MB total. Read current limits rather than relying on defaults.
- Pending submissions are frozen by the guide. Do not push task changes before
  review expecting them to be re-ingested. Keep working notes on the broader
  working branch; revisions after feedback use the same PR.

### 2026-11-03 — marked die, observable v3 rubric and fresh direct Dream runs

- Operator: repository agent; branch `roll-a-die`. User requested coloured
  faces/markings, the new rubric and fresh demo/Dream recordings. GPU startup
  succeeded around 13:58 UTC after the earlier regional capacity failures.
  The retained `/data/` installation survived; no cold installation was needed.
- Added six coloured faces and black 1–6 pips as non-colliding paint on the same
  16 mm / 5 g cube. Added a separate review camera and render-only reference rulers.
  Camera angle needed visual QA: the first low view hid the qualifying upper
  face, so it was raised and both final videos were recorded on the final setup.
- V3 uses visible pose/time criteria. The first v3 scripted release was tuned
  locally for reachable targets and speed limits, then scored 1.0 on the first
  new physics attempt. Final camera-matched demo002 also scored 1.0 after 182
  actions / 9.10 simulated seconds, wall 44.457 s. Cyan 5 up at 7.85 s → red 2 up at 8.00 s demonstrates
  the required inversion; rest is 8.10–9.10 s. Commands never move the die directly.
- Final direct Dream002 scored 0.0 with no qualifying pickup in 1,200 actions /
  60 simulated seconds; wall 184.133 s, 25 requests, 25 attempts, 1 session, no retries.
  Its 380 returned prediction rows beyond bounds include unused tail rows.
  Inspect's normal bounds clamp/per-step limiter remains enabled. Independent
  action-log checks found zero range or step-limit violations in executed actions.
- Final evidence: `artifacts/die-v3-demo-002/`, `artifacts/die-v3-dream-002/`;
  final media: `artifacts/roll-a-die-v3/`. Full videos contain 183 / 1,201 frames
  at 20 Hz, H.264/yuv420p with fast start, about 2.93 MB / 14.27 MB. The PNG is 0.67 MB.
  A separate quarter-speed turnover clip aids learning; the full videos preserve
  every original frame. Old raw artifacts and validation history remain intact.
- Final independent rescoring matches 1.0 / 0.0. All 48 tests pass: 35 scorer,
  10 bridge and 3 recording/source tests. Current core source hashes match both
  final run snapshots. Two new privacy-checked anonymous compressed traces are
  committed with `VALIDATION.json`; old evidence is in `VALIDATION-v2.json`.
- At the observed $3.28/hour rate, the final pair's 228.590 seconds of runner
  time estimates $0.208, excluding setup/idle/review iterations, shutdown,
  retained storage and Dream API charges. The complete batch includes one short
  render check, two demos, two Dream runs and elapsed preparation time. Use
  session/billing data below for the complete cost; do not add overlapping totals.
- All requested evidence was downloaded and the GPU was idle before stopping.
  Stop requested at 14:18:51 UTC; confirmed STOPPED at 14:24:57 UTC (about
  six minutes to stop). Start request 13:58:17 to confirmed stop is 26m40s;
  conservatively charging the full interval at $3.28/hour estimates **$1.46**
  for this whole batch. This is an elapsed-time estimate, not an invoice, and
  excludes later retained storage and Dream API charges. At 14:25:50 UTC posted
  credits were $196.06, versus $196.14 at 14:03:38 UTC. Billing lags, so this
  eight-cent posted change is NOT the full batch cost. Preserve the retained VM.
  Filtered lifecycle/billing evidence is local in `artifacts/die-v3-session/`.
- Dream credentials were transferred to the authorized team VM without display,
  owner-only under `~/.dreamlabs/`. No credential entered Git, logs or evidence.
  At that point, media and PR authorization were still pending. This is
  superseded by the later explicit authorization and submission entry above.

### 2026-11-03 — scoring v2 correction; GPU batch blocked by capacity

- Operator: repository agent; branch `roll-a-die`. User authorized scoring fixes
  and everything needed for readiness, while retaining the no-PR instruction.
- Shared branch fetched; VM confirmed stopped before requesting restart at
  13:07:55 UTC. Both that attempt and the 13:11 retry failed for regional GPU
  capacity. The planned two repeated demos and direct Dream run did not execute.
  VM confirmed STOPPED at 13:15:58 UTC; no key transfer or environment change.
  Posted credit was $196.16 ($3.84 total spend since the initial $200); billing
  lag/storage prevent attributing the change to these attempts.
- Scorer v2 requires a 90-degree maximum excursion from the verified release
  reference; accumulated rocking no longer earns roll credit. Historical
  trajectories were independently replayed; no evidence was overwritten.
  Results/hashes: `artifacts/die-v2-rescore-001/` and task `VALIDATION.json`.
  Three anonymous compressed trajectories are committed under the task
  `evidence/` directory so other agents/reviewers can reproduce scores offline;
  original raw media and local artifacts remain ignored.
  The demo's first v2 full-score time remains 9.30 s, matching its original
  termination, so no post-termination motion is needed for the corrected score.
- Media-token slot remains empty; user is looking for the Robocurve token.

### 2026-11-03 — first die task and operating agreement

- Code: initial validated implementation `6d38530`, branch `roll-a-die`.
- VM stopped at 12:21:26 UTC; verified stopped at 12:24 UTC. The stop request
  took about eight minutes to finish. Read the live state next session.
- Agreed to reuse one VM daily, develop locally in parallel and batch GPU work.
- User approved Dream-key transfer to the team VM when beneficial; not done yet.
- Recorded the scoring concern above; no task/scorer changes or new GPU trials
  were made during this documentation review. No competition PR is authorized.

For each new entry, record **date, operator/agent, branch/commit, question,
measured result, evidence path, cost basis, decision and remaining uncertainty**.
Update the working guidance when evidence changes it; preserve earlier dated
results and mark superseded conclusions explicitly. Pull the latest notes before
editing, merge both agents' findings, and commit/push the update with the work.
