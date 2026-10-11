---
name: robodojo-pick-from-conveyor-by-image
description: Image-conditioned conveyor collection with native-budget checks, staged bimanual handling and bounded task-specific experience.
---
# Conveyor skill v26 — stable core and bounded candidates

Scope: `pick_from_conveyor_by_image`, Ken's isolated `vlm_agent_rsi1` harness. Read `common.md` and official eight-frame VIDEO ICL only. Re-localize from current RGB; no hidden object poses or coordinate replay. The following maintenance rule supersedes older instructions to rewrite this task Skill after every episode.

## Stable core

1. Read the reference board and identify the target. Explicitly open both grippers. RIGHT handles the basket; LEFT handles the target. Stages: `basket -> intercept -> transfer -> place -> lift -> finish`.
2. Approach a visible basket handle/rim without descending through its wall or floor. Confirm retention by short displacement against the belt and persistence while the hand is stationary. Tilt, adjacency and opening near the empty baseline do not prove retention. Thick-handle grasp has repeated same-layout retention evidence; geometry/orientation must be re-localized.
3. Estimate arrival from unobstructed frames and actual native action duration. Do not close before the target reaches the closing region. `catch3d` closes from motion start; it is not automatic tracking. After closure, lift/retract briefly and verify that the object follows the hand before transport. For a ring-shaped target with an accessible hole, a finger through the hole and the other outside its solid rim retained it in two different layouts; approach from above if a low lateral motion pushes the ring. This is conditional shape-specific evidence, not a universal grasp. See [ring evidence](references/ring_grasp.json).
4. Keep arm paths and held objects clear. Carry the target above the rim, align the body rather than only the TCP over the interior, lower with current observations, release, then clear LEFT. Verify the target is inside a supported/level basket before lifting both together.
5. After failed or partial motion, reread actual robot pose before dependent actions. Do not push further through object contact or repeat unchanged unreachable commands. After repeated similar misses change region/orientation/approach. If no reachable clear recovery remains, stop without reset or idle budget draining.
6. Native success takes precedence when it truncates an unfinished motion. A visible placement alone is not native success. Current RGB evidence, historical native achievements and score events remain separate.

## Non-negotiable execution and acceptance

- Original limit **700 native control steps at25Hz**. Check remaining steps before each primitive; include complete planned motion, closure and maximum settling. Sync, holds, waits and resets count by actual execution. Keep per-control-step native truncation; never increase the limit, reset counters or bypass termination.
- Delivery requires `native_success AND valid_capture AND 0<native_steps<=700`. Failures remain in `run_logs`. No extra quality ranking or clean-trajectory filter before the requested collection quantity is met.
- Binary native score0..1: a single AND of target-on-basket-bottom and target-lifted. No intermediate point thresholds. Score delta0 is not failure. Only confirmed fresh scoring events and satisfied trigger conditions can establish a scored-stage miss; unknown is not failure. Do not wait repeatedly for unavailable diagnostics. A physically needed final settling window is at most8steps once.
- Privileged collection feedback is opt-in, read-only and sidecar-only, outside training RGB/state. No extra `get_reward/get_score/check_once/step` calls. `env.success` alone is invalid before terminal. Ordinary reads and environment steps are not `score_event` identifiers.
- Private Supervisor v1 is installed but defaults off; enable only at the next authorized episode boundary with its collection flags. Its integration has offline tests/replay, not online validation. Do not treat this Skill as authorization for another batch.
- Modify only this task's Skill/private harness. Do not change shared policy, official simulator/reward, `common.md`, other tasks or project `sources/`.

## Pending experience — at most3 distinct candidates

**C1: Stage LEFT above the target corridor.** Applicable when an open upstream finger blocks arrival. Raise clear, re-localize and descend with measured travel allowance rather than waiting against the object. Evidence: `20261001-132403`, steps201..230 showed blockage then clearance and capture by272; high staging in `20261001-135129` captured by251. Both same layout. Recovery has one observed use; retain as conditional candidate pending repeated validation. Added applicability from robodawn-pick_from_conveyor_by_image-20261004-182711: if the basket starts upstream of LEFT, keep LEFT outside the basket/arched-handle path until the basket passes, or stage above the entire basket rather than only above the target. At steps76..104, low LEFT staging obstructed/tipped the upstream basket; clearing LEFT at122 freed it, but recovery missed the target window. This is one-layout failure evidence, not a validated success-rate improvement.

**C2: Position the receiving basket before target capture and keep it fixed during transfer.** Applicable where the later handoff would otherwise move the basket through a held target's path. Evidence: `20261001-132403` retained target at318, then lost it during basket relocation/central approach by354; `20261001-135129` prepositioned basket before capture and succeeded. One complete successful trajectory; do not claim cross-layout reliability or step savings yet.

Additional bounded recovery evidence: if a held cup cannot enter the basket from a shallow down60 approach, do not repeat blocked lateral/downward commands. In `20261005-153816` seed1/layout18, lowering the basket alone did not resolve the blockage. LEFT retreated clear, then moved toward its base and lower in free space before an incremental30-degree roll made the approach steeper; retention was rechecked, transfer then succeeded, and native success occurred at522steps. The first roll attempt at a high central pose was IK-rejected. This is one observed recovery, not a universal cause diagnosis or validated improvement; preserve the actual grasp and check reachability and retention after each change. See [held-cup transfer recovery](references/held_cup_transfer_recovery.json).

**C3: Resolve ambiguous depth using matched RGB points and calibration.** Calibration must match the actual rendered image: legacy head-camera metadata reported fy336.46 while the measured tiled-render projection gives fx=fy288.13 at640x480. The private harness now derives K from validated current cameraProjection, verifies render-view/extrinsic agreement, and preserves both versions in sidecars. If calibration is absent while the annotator warms up, use raw RGB/proprioception and defer metric triangulation; do not reconstruct the legacy K. Evidence: seed0/layout54 `20261005-090636` and seed1/layout1 `20261005-093649`; three-camera projection round-trip checks passed. This validates a metadata correction, not a success-rate improvement. See [projection evidence](references/render_calibration.json). Applicable when a wrist cross aligns in projection but depth remains uncertain. Triangulate the same visible feature in two cameras, reject ray gaps>2.5cm, and re-read after motion. A single image ray is not a3D position; a guessed floor plane is an approximation. Evidence: `20261001-090216` handle attachment ray gap0.53cm; later logs include uncertain nose correspondences. Accuracy and benefit remain unvalidated across layouts. Added evidence: `20261004-232852` seed0/layout16 used a matched upper-arch point (ray gap0.522cm) to correct handle approach at70steps; both basket and ring were retained after probing at127 and native success occurred at291. An earlier correspondence with2.82cm gap was rejected. This is one successful recovery trajectory, not a depth-accuracy or success-rate validation. Ring-specific grasp details and placement/retreat contact remain in the run quality review.

Run IDs above are suffixes under `/ML-vePFS/model_partner/ken/run_logs/robodawn-pick_from_conveyor_by_image-<ID>/`. Exact coordinates and all trajectory details stay in those logs, not default context.

## Maintenance and on-demand references

- Repeated success with the same method updates external statistics only. Known failures increment external counts without repeating rules. No new finding means **no Skill edit**.
- Admit only a distinct new failure cause, recovery or materially cheaper method, with applicability and source evidence. Merge into the core after repeated validation within the stated scope; do not invent a universal validation count.
- At3 candidates, deduplicate/compress or remove invalid candidates first; retain useful evidence in history. Do not evict the whole long-term Skill by a sliding window. A read truncation is not full storage: split or read in sections.
- Change only between episodes. Before replacing a version, preserve its full text and hash under `history/`. Trajectories remain in logs; do not load them all each decision.
- For rule ambiguity or integration work, read [rules and integration](references/rules_and_integration.json), which records official commit/source links and verified scope. Browse official sources when rules remain unclear and compare against current server code; do not change native scoring from prose or video.
- For statistics/repeated-failure counts, read [external statistics](statistics.json); for an older rationale, inspect [archived v20](history/SKILL_v20.md). These references are not default execution context.


## 候选经验补充 — 隔壁组参考，2026-10-10

仅在下述异常出现时参考；原有任务规则、预算及成功流程保持优先。只调用我们现有原语，不引入对方工具、坐标或服务。尚未在我们的执行链路验证，不作为成功率提升结论。

篮筐已经可靠落在支撑面、开爪后仍勾住把手时，不把“已开爪”当作“已脱离”。先用当前画面检查指间接触与撤离通道；自由脱离后直接撤出。仍勾挂时，只在可见净空内用现有原语短段调整、重新观察；篮筐被带动或倾斜就停止，不强拉。篮筐悬空或支撑不明时不使用此分支。持篮臂仍承担支撑时，不把它改作观察臂。

来源：隔壁组 basket-handle-regrasp；完整原文与哈希见本候选版 change-manifest.json。
