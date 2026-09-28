# NOTES.md

Overflow detail for `CLAUDE.md`, which is capped at 300 lines. CLAUDE.md stays
authoritative for decisions; this file holds the measurements and derivations
behind them. Referenced from CLAUDE.md §8 by date.

---

## 2026-09-08 — Palm orientation and pad geometry

Measured with a throwaway diagnostic (`tools/check_palm_orientation.py`) that
drives the real 4-joint / 6-D elbow+wrist IK (D2, D3) with `mj_forward` only, so
the poses are subject to the same constraints the live teleop is.

### Hand geometry

The `{left,right}_rubber_hand` mesh is **0.045 × 0.106 × 0.143 m**. In the
`wrist_yaw_link` body frame:

| axis | maps to body frame | meaning |
|---|---|---|
| longest, 0.143 m | `+x` — `(0.965, ∓0.260, -0.034)` | fingers, continuing the forearm |
| thinnest, 0.045 m | `y` (purity 0.964) | palm-plane normal |

The palm centre is **0.106 m distal** of the `wrist_yaw_link` origin. Aiming IK
at the wrist origin therefore puts the palm *past* the box by ~10 cm; the
diagnostic re-targets so the palm, not the wrist, lands on the face.

### Pad slide axis (build parameter)

Pressing direction in the `wrist_yaw_link` body frame:

- left `(-0.261, -0.964, -0.043)`
- right `(-0.261, +0.964, -0.043)`

Mirrored: the two differ **only in the sign of y**. Do not declare `axis="0 1 0"`
— pure y is 15.4° off the palm normal and would press on an edge. Either use the
exact vector or give the pad body its own quat.

Stroke must be **≥ ±0.05 m**: the 4-DOF IK's palm-to-goal residual is 26–54 mm
across the grid below.

### Why WRIST_NATURAL was NOT retuned

The pad mount absorbs any *constant* offset between palm normal and press
direction, so flushness at one pose is not the metric. What cannot be designed
away is how much the palm→box direction **varies** as the box moves. Measured
over reach 0.26–0.38 m × lateral ±0.08 m:

| wrist config (roll, pitch, yaw) | spread max / rms | IK palm error mean / max |
|---|---|---|
| current `(+0.30, +0.20, 0.00)` | 26.1° / 12.1° | 28 / 49 mm |
| flushness-optimal `(-0.40, +0.80, +0.40)` | 28.7° / 13.3° | 32 / 54 mm |
| all flat `(0, 0, 0)` | 26.4° / 12.3° | 26 / 44 mm |

Essentially identical. The spread is driven by box position, not wrist pose, so
retuning buys nothing and would invalidate every arm pose already tuned by feel.

**Consequence for the pad design:** it must tolerate ±26° of incidence. A small,
hard, flat pad contacts on an edge at that angle. Prefer a generously sized pad
with soft `solimp`, or a slightly rounded contact face.

**Opposition:** the two press normals are ~150° apart, not 180°, so pad forces do
not fully cancel and leave a small net push on the box. This is a concrete
mechanism behind the O2 slip risk.

### MuJoCo gotcha worth remembering

`model.mesh_vert` is **not** in the body frame. MuJoCo re-expresses mesh vertices
in the mesh's own principal-axis frame and stores the compensating rotation in
`geom_quat` — so `g1.xml` can say `quat="1 0 0 0"` while the compiled
`geom_quat` is not identity. Use `data.geom_xmat`, which folds it in. Reading
`mesh_vert` raw gives a plausible-looking but wrong answer.

---

## 2026-09-08 — Name-based model indexing

`g1_teleop/indices.py` (`ModelIndex.resolve(model)`) replaced every hardcoded
qpos/qvel/ctrl offset. Joint-name lists in `g1_teleop/config.py` are the source
of truth.

### What the pad joints actually shift

Verified by building a throwaway copy of `g1.xml` with a pad slide joint inside
each `wrist_yaw_link`:

| block | before | after | literal survives? |
|---|---|---|---|
| base `qpos[0:7]` | 0:7 | 0:7 | ✅ root freejoint is always first |
| legs `qpos[7:19]`, `qvel[6:18]` | 7:19 | 7:19 | ✅ legs precede the insertion |
| leg `ctrl[0:12]` | 0:12 | 0:12 | ✅ |
| waist + left arm | 19:29 | 19:29 | ✅ |
| **right arm qpos** | 29:36 | **30:37** | ❌ off by one |
| **box freejoint qpos** | 36:43 | **38:45** | ❌ off by two |
| upper `ctrl[12:29]` | 12:29 | 12:29 if pad actuators appended | ⚠️ shifts if interleaved |

That is the dangerous shape: legs and left arm stay correct, right arm and box
break, and the robot still walks.

### Load-time assertions

`ModelIndex.validate()` raises on:

1. a joint or actuator renamed/dropped (`ValueError` from the name lookup);
2. a resolved block whose count no longer matches the config name list;
3. `model.nu` not fully accounted for by the known actuator lists — i.e. an
   actuator added without updating `config.py`;
4. a name list reordered relative to the model, which would silently mis-map the
   positional `KPS` / `KDS` / `DEFAULT_ANGLES` vectors and the policy's 12
   actions. **This is the one that would be near-impossible to debug by eye.**

Gaps are explicitly allowed: pad joints and actuators may be declared anywhere
in the XML. A non-contiguous block resolves to an index array instead of a
slice, which reads and assigns identically.

### Equivalence evidence

- Every resolved index is bit-identical to the literal it replaced.
- `walk_test`'s control law over 5000 steps (10 s): trajectory SHA-256 prefix
  `7521d5f83b160899b8f6899c4440ca45` before and after, min base height 0.7705 m,
  hold error 0.0370 m, max arm error 0.010070 rad.

---

## Planned learning-code layout (overflow from CLAUDE.md §5)

Lives at the **repo root**, as siblings to `g1_teleop/`, so the recorder can
import the existing teleop stack unchanged. (Earlier drafts of CLAUDE.md said
`g1_vision_teleop/`; that duplicate folder was deleted in commit `f2d0051` on
2026-09-07 and the repo root is now the project.)

```
g1_data/   spec.py  episode.py  recorder.py  reset.py  phases.py  success.py  dataset.py
g1_policy/ base.py  bc.py  act.py (ACT + ACT-LSTM behind use_lstm flag)  ensemble.py
g1_train/  train.py  config.py  normalize.py
g1_eval/   deploy.py  experiments.py  metrics.py
configs/   task.yaml  record.yaml  train_{bc,act,act_lstm}.yaml
data/      raw/<episode_id>.npz   processed/
```

---

## 2026-09-08 - Palm pads built (CLAUDE.md section 8)

### Slide axis: face normal, NOT palm normal

Three candidates compared in the `wrist_yaw_link` body frame, scored against the
per-pose box face normal over reach 0.26-0.38 m x lateral +-0.08 m:

| candidate | max dev | rms dev | force efficiency |
|---|---|---|---|
| palm-plane normal `(-0.261, -/+0.964, -0.043)` | 43.0 deg | 34.8 deg | 0.821 |
| mean palm->box centre `(-0.051, -/+0.859, +0.510)` | 21.8 deg | 13.3 deg | 0.973 |
| **mean box FACE NORMAL `(0.111, -/+0.906, +0.408)`** | **11.9 deg** | **7.1 deg** | **0.992** |

Normal force acts along the face normal; any tangential component drags the box
along its own face instead of squeezing it. The palm normal describes where the
*hand* points, which stops mattering once you author the pad mount. **Built with
the face normal.** Assumes the operator squares up to the box - box orientation
is fixed and world-aligned, so a large heading offset rotates this.

### As built

Per hand, a child body of `wrist_yaw_link`: body `pos` = palm centre pulled
0.035 m back along the press axis, `quat` putting pad-local +x on the face
normal, slide joint `range="0 0.10"`, box geom `size="0.005 0.035 0.035"`,
`friction="2.0 0.05 0.001"`, `condim="4"`, `priority="2"`, `solref="0.008 1"`,
`solimp="0.85 0.92 0.004"`. Sites `{left,right}_palm_site` sit on
`wrist_yaw_link` at the palm centre - deliberately on the hand, not the pad, so
EE pose does not move with gripper aperture. (Section 6 says "pad sites";
hand-frame EE plus the separate gripper dim carries the same information without
the correlation.)

### Actuator: why kp=15 is not a typo

`<position gear="10" ctrlrange="0 1" kp="15" kv="0.3" forcerange="-2 2"/>`.
Effective joint stiffness is `gear^2 * kp` = 1500 N/m, i.e. 7.5 N at 5 mm
compression. Writing `kp="1500"` with `gear="10"` would give 150 kN/m. The
`gear = 1/stroke` is what puts the 0-1 action contract in the XML.

**`forcerange` is the real grip-force setting**, not kp: commanded full closure
leaves ~70 mm of servo error, so the servo demands ~105 N and simply sits at the
cap. +-2 -> 20 N at the joint.

### TR11 in detail - the base-pinning test artifact

The first contact rig pinned the floating base by overwriting `qpos[base]` after
every `mj_step`, with limp legs. The robot sagged each step and was teleported
back up; the box, held only by friction, was not. The box ratcheted downward at
a constant ~20 mm/s that was **invariant to press force (20-200 N), mu (2-8), pad
area, `solimp`, `solref`, `impratio`, cone type and `noslip_iterations`** - that
total insensitivity to every physical parameter is what exposed it as an
artifact rather than slip. Correct rig: `body_gravcomp = 1` on all robot bodies
and 0 on `box1`, so there is no sag to correct, *plus* base pinning so the now
weightless robot cannot float off its feet. Either fix alone fails: gravcomp
without pinning lets the robot fly up off the floor contact.

### Residual creep - genuine, and it is O2

On the corrected rig, as built: 8 sustained pad-box contacts, **Fn 40.08 N**,
Ft 3.93 N (= the 3.92 N box weight), creeping down at **6.2 mm/s**. Friction is
not the limit (Ft/Fn = 0.098 vs mu = 2.0) - this is soft-contact tangential
creep, and `solref` is already clamped at 2x timestep, with the timestep fixed
at 2 ms by the locomotion policy.

Escalation ladder, corrected rig (drop over 5.2 s / steady creep):

| variant | drop mm | creep mm/s |
|---|---|---|
| as built | 32.3 | -6.2 |
| joint force 50 N | 22.7 | -4.4 |
| joint force 100 N | 22.5 | -4.3 |
| mu = 4 | 695 | unstable, box ejected |
| mu = 8 | 45.3 | +5.8 |
| pad half 0.05 m | 31.1 | -6.0 |
| solref 0.004 | 35.5 | -6.8 |
| solimp 0.99/0.999/0.001 | -12.8 | +2.4 (pushed UP) |
| impratio 50 | -20.7 | +3.9 (pushed UP) |

Note the sign flip: soft contact lets the box slide down, hard contact squirts it
upward. Neither holds it still, so this wants a tuning pass against a real
scripted grasp rather than more isolated parameter sweeping. Raising press force
is the only monotone improvement found.

---

## 2026-09-08 - O3 and O4 fixed (box spawn)

### O3 - spawn region

Platform half-extent 0.18 m, box half-width 0.09 m, both axis-aligned and the
box orientation is fixed, so the bound is per-axis, not radial:

    pickup_half + box_half + margin <= platform_half
    0.07        + 0.09     + 0.02   =  0.18

`pickup_half` 0.13 -> **0.07**. The old value put a corner spawn 0.22 m from the
platform centre - a 4 cm overhang. `box_reset.assert_spawn_fits` re-derives the
bound from the model's geom sizes at `G1Robot` load, so a Q6 platform resize is
picked up automatically rather than silently invalidating the config number. The
platform itself was NOT resized (Q6 may change it).

### O4 - randomisation on the stepped model

Root cause was two code paths, not a missing one: sampling lived inline in
`G1Robot.reset_box`, which only ever touches the kinematic twin. The stepped
physics model had no equivalent, so every episode started from the keyframe box
pose and ten runs of the 10/10 gate were one run repeated.

Fix: `g1_teleop/box_reset.py` is the single implementation, taking any
`(model, data, ModelIndex)`. `G1Robot.reset_box` delegates to it;
`run_integrated_combined.py` calls it on the physics model at startup with an
episode seed (`python run_integrated_combined.py <strategy> <seed>`), and seeds
the twin identically so the two models cannot drift apart again.

`sample_box_pose(cfg, seed)` is a **pure function of the seed**, not a stateful
RNG stream: reproducing episode 7 means passing 7, not replaying 0-6. That
matters for Objective 4, where specific held-out box positions have to be
re-runnable on demand. Position only - box orientation is fixed by the thesis
constraints, so the quaternion is always identity.

### Verification

Ten seeds, robot teleported 6.5 m away, 2 s of physics each:

- 10 of 10 poses distinct; spawn x spanned 1.442-1.562, y spanned -0.037-0.068.
- All four footprint corners on the platform for every seed, before and after.
- Settle: drift 0.00 mm, drop 0.14 mm (contact settling), tilt 0.00 deg.
- Contact check is explicit, not assumed: the only geom the box touched in any
  run was `platform_pickup_geom`. No robot contact.
- Seeds 0, 3, 7 reproduce their exact pose on a second call.
- `assert_spawn_fits` raises on the old `pickup_half=0.13`.
- `walk_test` trajectory hash unchanged (`fd8cd9be...`).

### Still open before the 10/10 gate

O4 gives *variation*; it does not give an episode loop. Nothing yet resets the
robot pose, legs, pads and box together and steps a bounded episode - that is
the recorder's `reset.py` (section 5). The gate also still needs O2 resolved:
the grasp creeps at 6.2 mm/s at rest.

---

## 2026-09-08 - Q6 CLOSED: what generalization is measured over

### The decision

Randomize **box position only**. Both platforms keep fixed world positions.
Enlarge the pickup platform so sampled box positions span a visibly different
range. Hold out an **interior band** of the pickup region for the Objective 4
evaluation - not the far half.

### Why an interior band and not a far-half split

1. **A far-half split tests extrapolation, and extrapolation floors every
   policy.** When BC, ACT and ACT-LSTM all score ~0 the comparison has no
   discriminative power, and the three-way ablation is the contribution. An
   interior band tests interpolation, where the policies can actually separate.
2. **Difficulty must be comparable between train and test.** Any split that puts
   test positions at a systematically different mechanical difficulty confounds
   "failed to generalize" with "the grasp was harder there". An interior band
   keeps both sides of the split at the same difficulty by construction.

Point 2 was originally justified by "the IK palm-to-goal residual grows with
reach (15 mm near, 61 mm far)". **That is backwards, and it does not apply
anyway** - see the correction below. The conclusion stands; the stated mechanism
did not.

### Correction: IK residual vs reach

Measured at the current `WRIST_NATURAL`, palm-to-goal residual against
base-to-box reach:

| reach m | 0.22 | 0.26 | 0.30 | 0.34 | 0.36 | 0.38 | 0.40 | 0.42 |
|---|---|---|---|---|---|---|---|---|
| residual mm | 62.3 | 48.7 | 33.4 | 17.7 | 11.0 | 10.2 | 16.8 | 25.3 |

The residual is **worst at NEAR reach** and best around 0.36-0.38 m. So near
positions are the mechanically harder ones, not far.

More importantly, the mechanism does not transfer to box *world position* at
all. Reach is base-to-box distance, and the operator chooses where to stop
(`GRASP_MIN..GRASP_MAX` = 0.20..0.34 m). A box further away in world x does not
produce a longer reach - it produces a longer *walk*, after which the operator
stops at whatever standoff is comfortable. Box world position and grasp
difficulty are therefore only weakly coupled, and the residual curve is not a
reason to prefer any particular split.

### Why platform-position randomization was rejected

Recorded as TR13. In short: it converts Objective 4 from manipulation
generalization into navigation generalization; it puts the unreliable locomotion
path on the critical path of every single episode; and it inflates the sampling
space to 4-6 dimensions, which 100-150 demonstrations cannot cover densely
enough to discriminate between three policies.

### Scope, for the limitations section

Generalization is evaluated over **manipulation targets** (box position), not
**navigation targets** (platform position). Locomotion stays in the task but is
held constant so it cannot confound the comparison. Robustness to novel scene
layouts is therefore untested, and would be required before any physical
deployment. This must appear in the limitations section, not be left implicit.

---

## 2026-09-08 - Q6 geometry: the x axis is capped by the pelvis

Measured, not assumed (`walk_test.DEFAULT_ANGLES` operating crouch, box parked
away, robot swept toward the platform until first robot/platform contact):

- The **pelvis** is the limiter. It cannot pass under a 0.75 m surface, and
  thinning the slab does not help - the pelvis mesh is tall enough to hit a
  2 mm-thick slab at 0.748 just as it hits the current 40 mm one.
- **Max base x = 1.25-1.26**, essentially independent of platform half-extent
  and slab thickness. Beyond that the hips join in.
- With `GRASP_MAX = 0.34`, that caps reachable box world x at **~1.59**.

Consequence for enlarging the platform along x: the near edge advances toward
the robot exactly as fast as the far edge retreats, so growing `half_x` moves
the far sample edge out of reach without buying usable span.

| platform half_x | near edge | max base x | reach limit | far sample edge | verdict |
|---|---|---|---|---|---|
| 0.18 (current) | 1.32 | 1.25 | 1.59 | 1.57 | OK |
| 0.20 | 1.30 | 1.25 | 1.59 | 1.59 | at the limit |
| 0.22 | 1.28 | 1.25 | 1.59 | 1.61 | unreachable |
| 0.30 | 1.20 | 1.25 | 1.59 | 1.69 | unreachable |

**The x span is capped at about 18 cm.** The y axis has no equivalent
constraint: the robot approaches from -x and positions itself in front of the
box, so `half_y` can grow freely.

---

## 2026-09-08 - Related work: Singh et al., SII 2026

"Expert-Guided Imitation for Learning Humanoid Loco-Manipulation from Motion
Capture" - https://paleziart.github.io/guided-humanoid-locomanipulation/

Positioning notes for the RRL and the defence:

- They train on a **single motion capture recording**. Our contribution is a
  demonstration-collection pipeline over many demonstrations, which is a
  different data regime.
- **Do not conflate their "BC" with ours.** Their method is RL tracking a motion
  reference, with an auxiliary behavior-cloning loss that supervises the LEGS
  from a pre-trained walking expert. That is teacher-student distillation of
  another policy. Our BC baseline is behavior cloning from human
  demonstrations. Same acronym, different method - the RRL must say so
  explicitly or a reader will assume we are duplicating their baseline.
- They use **three separate policies** (pick-up, drop-off, return) switched by a
  phase clock. This is the direct alternative to our single recurrent policy and
  is a likely panel question. Our answer: policy switching requires
  hand-specified phase boundaries and a switching controller - task structure
  engineered in by hand - whereas a single policy has to learn the phase
  structure from data. Which is better is an empirical question, and it is
  precisely what our three-way ablation answers.
- For long distances they use a **2D Dubins planner** to feed fake intermediate
  targets so the policy's inputs "remain in-distribution". That is engineering
  *around* out-of-distribution inputs, not learned generalization. Objective 4
  measures the thing they routed around - worth stating plainly.
- They did **not** have our marching-in-place problem (TR1-TR4). Their issue was
  that directly mimicking human strides gave unstable contacts and
  unrealistically long strides. Different problem. **Do not cite them as
  precedent for our locomotion limitation.**
- Their domain randomization (dynamics, pushes, terrain) serves sim-to-real. We
  are simulation-only, so it buys us nothing and should not be copied.

---

## 2026-09-08 - Two additions to the evaluation plan

1. **Data-scaling curve.** Retrain all three policies on 25/50/100/150-demo
   subsets. Nearly free once the training loop exists, and if the ACT-LSTM
   advantage concentrates in the low-data regime that is a genuine
   sample-efficiency finding rather than a single aggregate number.
2. **Per-phase failure taxonomy.** Categorize every failure by phase and cause.
   If the ACT-LSTM advantage concentrates at phase transitions, that is direct
   evidence for the partial-observability mechanism the LSTM is supposed to
   address - a mechanism result, not just a score.

Both depend on the recorder logging a phase label at every timestep.

---

## 2026-09-08 - Planned Chapter 3 figures

Generate **from the same constants the code uses** (`BoxConfig`, the platform
geoms in `scene.xml`), so a figure cannot drift from the implementation the way
a hand-drawn sketch would.

1. **Top-down pickup platform.** Platform outline at true dimensions, training
   region shaded, held-out band hatched, box footprint to scale, coordinate axes,
   robot position. *After collection*, overlay the actual sampled box positions
   from every episode as a scatter - that turns a design sketch into evidence of
   coverage, and makes any gap in the sampling visible.
2. **Goal platform** with the Q4 `d_place = 0.10 m` acceptance radius drawn to
   scale against the box footprint, so the reader can see how tight the
   place-success criterion actually is.

Companion check, to run at the end of collection: **assert that no recorded
episode's box position falls inside the held-out band.** A single leaked episode
silently converts Objective 4 from held-out to in-distribution.

---

## File and module structure (overflow from CLAUDE.md section 11)

**Existing** — paths relative to the git repo `g1_vision_teleop/` unless prefixed `../`.
- `../docs/Thesis_Proposal.pdf` — 62 pages; Ch.3 methodology at PDF pages 33–56.
- `run_teleop.py` — kinematic ZED teleop, interactive viewer. `run_teleop_combined.py` — same,
  single OpenCV window, offscreen render.
- `run_integrated_combined.py` — full stack: physics + locomotion + ZED arms.
- `walk_test.py` — locomotion policy only, stepped physics, no ZED.
- `locomotion_input.py` — `PelvisVelocity`, `LeanJoystick`, `KeyboardCommand`. **Do not delete**
  — `PelvisVelocity` is the evidence for the §3.3.4 negative result (D6).
- `scene.xml` — platforms, goal marker, box. `g1.xml` — G1 29-DOF MJCF, actuators, keyframe
  `stand`, IMU sensors.
- `g1_teleop/config.py` — all tunables as dataclass configs.
- `g1_teleop/transforms.py` — camera→robot rotation, torso yaw helper.
- `g1_teleop/retargeting.py` — geometric scaling to elbow/wrist targets.
- `g1_teleop/ik.py` — damped least-squares IK with nullspace seed-pull.
- `g1_teleop/robot.py` — model wrapper, index resolution, twin box reset.
- `g1_teleop/indices.py` — `ModelIndex`: name-based qpos/qvel/ctrl resolution + load assertions.
- `g1_teleop/box_reset.py` — seeded box spawn for any model + O3 platform-fit assertion.
- `../NOTES.md` — overflow detail for this file: measurements, derivations, index-shift tables.
- `g1_teleop/teleop.py` — per-frame controller: NaN guard, IK, smoothing, stillness lock.
- `g1_teleop/` also: `onceuro.py` One-Euro filter, `overlay.py` debug overlay, `zed_source.py`
  ZED/BODY_38 wrapper, `gating.py` DEAD (kept only for `RejectReason`).
- `../unitree_rl_gym/deploy/` — `pre_train/g1/motion.pt` locomotion policy,
  `deploy_mujoco/configs/g1.yaml` reference gains. `../test/*.py` — stale scratch, not current.

**Planned** — see §5 for the full layout of `g1_data/`, `g1_policy/`, `g1_train/`, `g1_eval/`.

---

## Verified vs assumed, in full (overflow from CLAUDE.md section 13)

**Verified by loading the model or reading files:** all four entry points; the kinematic-vs-
actuated split; `N_IK_JOINTS=4`, pinned wrists, 6-D elbow+wrist task; locomotion policy path,
obs layout, decimation, gains; scene geometry and keyframe; nq/nv/nu; collision geoms; absence of
recorder/dataset/training/eval code; O6 dead code; O7 contradictions; proposal §3.3–§3.9 with
Tables 3.1–3.6. 2026-09-08: `pyzed` installed; rubber-hand mesh axes; pad press direction and
contact force; resolved indices equal the literals they replaced.

**Assumed, not verified:** that `run_integrated_combined.py` runs end to end here (never
executed — needs a ZED); that the ZED is a 2i specifically (the
proposal says only "ZED stereo depth camera" and no code names a model); that box
friction/solref and the position-hold gains were tuned rather than inherited.

---

## Q1–Q5 full rationale (overflow from CLAUDE.md section 8)

- 2026-08-23 (Q1) — Gripper = one slide joint + one `<position>` actuator + one high-friction
  collision pad per hand, pressing opposite box faces. Reason: gives the proposal's 0–1 command
  real physical meaning, and decouples press force from arm IK, so the arm holds a clean pose
  instead of sitting in permanent IK error that would corrupt the 14 arm dims it is recorded
  into. Chosen over a weld because a contact-and-friction grasp is defensible at panel.
- 2026-08-23 (Q2) — Pelvis-velocity trigger abandoned; `KeyboardCommand` is the demonstration
  interface. Reason: TR1. `locomotion_input.py` is **kept** — `PelvisVelocity` and its
  diagnostics are the evidence for the §3.3.4 negative result. Do not delete it.
- 2026-08-23 (Q3) — Record and run the policy at **25 Hz**; locomotion inner loop stays at 50 Hz.
  Reason: keeps the proposal's stated rate (one fewer deviation), halves sequence length, and the
  two loops have no reason to be locked together.
- 2026-08-23 (Q4) — `d_place = 0.10 m` XY from box centre to goal centre, **and** the box resting
  on the goal platform and roughly upright. Reason: 0.06 m (the marker radius) demands
  near-perfect centring and would floor place-success for all three policies, destroying
  discrimination. The resting clause stops a box at the right XY but on the *floor* from scoring.
- 2026-08-23 (Q5) — Waist pinned at 0 (D10). Reason: fewer collection failure modes; turning is
  handled by `wz`. Dims kept as constants so the vectors still match proposal Tables 3.3/3.4.
- 2026-08-23 (Q6) — Provisional: enlarge the pickup platform, split along **x** (distance from
  robot), near half = training, far half = held-out. Reason: approach distance is the axis that
  stresses the policy; a left/right split is weaker because the robot can just turn. Revisitable,
  but must close before Phase 2 does.

---

## 2026-09-08 - Q6 FINAL NUMBERS (applied)

| quantity | value |
|---|---|
| pickup platform half-extent | x **0.19**, y **0.32** (0.38 x 0.64 m slab), centre (1.5, 0), top 0.75 |
| sample region | x [1.42, 1.58], y [-0.21, 0.21] — `BoxConfig.pickup_half = (0.08, 0.21)` |
| span | **16 x 42 cm** |
| held-out patch | x [1.47, 1.53], y [0.04, 0.16] — **6 x 12 cm**, 10.7% of sample area |
| reach limit | 1.595 = `max_base_x` 1.255 + `grasp_max` 0.34 |
| far sample edge | 1.580 -> **margin 0.015 m** |

`half_x` is 0.19 rather than 0.20 deliberately: 0.20 puts the far edge at 1.590
against a 1.595 limit, i.e. 5 mm, which fails silently if `GRASP_MAX`,
`DEFAULT_ANGLES` or the platform height ever drifts. 1 cm of span is a cheap
price for a margin an assertion can defend.

### Why a 2-D interior patch and not a y-only band

Both marginals stay in distribution: every held-out x [1.47, 1.53] appears in
training at some other y, and every held-out y [0.04, 0.16] appears at some other
x. Only the *combination* is unseen. That makes Objective 4 **compositional
generalization strictly inside the convex hull of the training data** - a
genuinely different claim from either extrapolation or interpolation along a
single axis, and a stronger one to defend.

The rejected alternatives fail in opposite directions:

- a **far-half split** is extrapolation, which floors all three policies;
- a **y-only band** risks being solved by squaring up to the box, which would
  ceiling all three policies.

Either way the comparison stops discriminating, and the three-way ablation is
the contribution. The patch is the only option that leaves room for the
policies to separate.

### Verification (2000 seeds + 10 settled episodes)

- Every footprint on the platform; sampled x 1.420-1.580, y -0.210-0.210.
- 199/2000 seeds (10.0%) landed in the held-out patch vs 10.7% by area.
- Every sample within the reach limit (max 1.580 vs 1.595).
- 10 seeds settled 2 s with zero drift, zero tilt, touching only
  `platform_pickup_geom`.
- All six guards raise when violated: `pickup_half` too big on x, too big on y,
  passed as a scalar; far edge past the reach limit; held-out patch not strictly
  interior in x, and in y.

### Constants relocated

`GRASP_MIN` / `GRASP_MAX` moved from module-level literals in
`run_integrated_combined.py` into `GraspConfig`, joined by the measured
`max_base_x = 1.255`. As literals in an entry point they were invisible to every
assertion - the same failure class as O3. `assert_reach_fits` now checks the
spawn region against them at model load.

`max_base_x` is **measured, not derived**: the pelvis cannot pass under the
0.75 m platform top, and the limit holds at 1.255 essentially regardless of
platform half-extent, because once the base is inside the footprint the pelvis
meets the slab from beneath. Re-measure if the platform height, slab thickness,
or `DEFAULT_ANGLES` changes.

---

## 2026-09-08 - Episode reset, and the state audit behind it

`g1_data/reset.py`. Every holder of per-episode state now owns a `reset()`;
`reset_episode` calls them. Reaching into another module's private attributes
from the reset would break silently the first time that module changed.

### THE LOCOMOTION POLICY IS AN LSTM

`unitree_rl_gym/deploy/pre_train/g1/motion.pt` is **recurrent**. Its TorchScript
`forward` reads `self.hidden_state` and `self.cell_state` (each `(1, 1, 64)`),
runs an LSTM `memory` module, and **copies the new h/c back into those buffers
in place**:

```
memory = self.memory
_1 = (memory).forward__0(torch.unsqueeze(x, 0), (hidden_state, cell_state))
out, _2 = _1 ;  h, c = _2
_3 = torch.copy_(torch.slice(self.hidden_state), h)
_4 = torch.copy_(torch.slice(self.cell_state), c)
return (self.actor).forward(torch.squeeze(out, 0))
```

How it was found: same seed gave identical state after reset but divergent state
after 50 stepped frames. Feeding one constant observation repeatedly produced a
*smoothly drifting* output — not the jitter of sampling, and `torch.manual_seed`
did not fix it, which ruled out RNG. Diffing `named_buffers()` across a forward
pass named the two culprits directly.

Consequences:

- **This was never known or documented.** CLAUDE.md described the policy as
  "47-D obs, 12 actions", implying feedforward. It never mattered because both
  entry points load the policy fresh per process and run one continuous episode.
  An episode loop makes it matter on episode 2.
- Without `reset_policy_state`, episode N begins with the LSTM still holding
  episode N-1's gait memory. Verified: omitting `policy=` from `reset_episode`
  changes the trajectory 50 frames later.
- **Thesis angle.** The thesis argues recurrence helps manipulation under
  partial observability (ACT vs ACT-LSTM, D8). The locomotion policy the whole
  task stands on is *already* an LSTM. That is supporting evidence for the
  premise and a good answer to "why would recurrence help here?" — it is the
  standard choice for partially-observed control, and this project was relying
  on one without realising it.

### Full state audit

| # | State | Where | Handled |
|---|---|---|---|
| 1 | qpos, qvel, qacc | `MjData` | `mj_resetDataKeyframe` |
| 2 | **qacc_warmstart** | `MjData` | same — invisible solver warm start; hand-clearing qpos/qvel alone leaves it and breaks bit-reproducibility |
| 3 | ctrl | `MjData` | same, then explicit pad/upper overrides |
| 4 | time | `MjData` | same |
| 5 | qfrc_applied, xfrc_applied | `MjData` | same |
| 6 | contacts / ncon / constraints | `MjData` | same, recomputed by `mj_forward` |
| 7 | act (actuator activation) | `MjData` | n/a — `na == 0` |
| 8 | mocap | `MjData` | n/a — `nmocap == 0` |
| 9 | legs | qpos | -> `DEFAULT_ANGLES`, not the keyframe (D5/TR5) |
| 10 | waist + arms | ctrl | -> keyframe targets, zero error on frame 0, no jolt |
| 11 | pad joints + actuators | qpos/ctrl | -> retracted |
| 12 | box freejoint | qpos/qvel | -> seeded `sample_box_pose` |
| 13 | **counter** | loop local | -> 0. Gait phase derives from it |
| 14 | action | loop local | -> zeros; it is fed back into the obs |
| 15 | target_leg_pos | loop local | -> `DEFAULT_ANGLES` |
| 16 | obs | loop local | -> zeros |
| 17 | hold_target | loop local | -> base XY *after* reset |
| 18 | hold_yaw | loop local | -> base yaw *after* reset |
| 19 | cmd | loop local | -> zeros |
| 20 | wall_start | loop local | **re-stamped**, not zeroed — wall-clock pacing reference |
| 21 | **hidden_state, cell_state** | the policy | -> zeroed. See above |
| 22 | prev_left, prev_right | `TeleopController` | `.reset()` |
| 23 | _coast_count, _have_good_pose | `TeleopController` | `.reset()` |
| 24 | _depth_state | `TeleopController` | `.reset()` |
| 25 | _still_state | `TeleopController` | `.reset()` |
| 26 | _shoulder_snapshot | `TeleopController` | `.reset()` |
| 27 | _counts, _last_reason, _frame_i | `TeleopController` | `.reset()` (cosmetic) |
| 28 | One-Euro `_x`, `_dx`, `_x_prev` | `KeypointFilter` | `.reset()` — 3 filters per keypoint, one per axis |
| 29 | cmd, _pressed | `KeyboardCommand` | `.reset()` |
| 30 | precision | `KeyboardCommand` | **persistent** by default (operator preference); `keep_precision=False` for determinism |
| 31 | _hist, _above_since | `PelvisVelocity` | `.reset()` |
| 32 | active, _gesture_since, _toggle_latch, _neutral | `LeanJoystick` | `.reset()` |
| 33 | twin `MjData` box | `G1Robot` | `twin.reset_box(seed)` — same seed as the physics model |
| 34 | MjModel | — | **persistent**, immutable scene |
| 35 | policy weights | — | **persistent**, immutable |
| 36 | ZED camera + grabber thread | — | **persistent**; re-opening per episode costs seconds |

### Verification

1. Same seed twice: identical fingerprint after reset **and** after 50 stepped
   frames (`3bce9530...` / `703303d5...`).
2. Three seeds: box poses all differ, robot fingerprint identical across all
   three.
3. Mid-episode reset from a walking robot with pads closed at 0.099 and
   `counter=600` reproduces the fresh-reset fingerprint exactly — and, stepped
   50 frames further, still matches (`fcdd26a0...`), which is what proves the
   LSTM was restored. Control: omit `policy=` and it diverges (`2687395e...`).
4. Reset + 200 policy-driven frames: base height min 0.7703, no fall, box still
   on the platform.

Also: `LocomotionConfig` consolidates `DEFAULT_ANGLES`, `KPS`, `KDS`, gait and
obs scales, which were duplicated verbatim between `walk_test.py` and
`run_integrated_combined.py` and would have become a third copy in the reset.
Verified byte-identical across both before consolidating. `walk_test` trajectory
hash unchanged (`fd8cd9be...`).

---

## 2026-08-23 decision block (overflow from CLAUDE.md section 8)

- 2026-08-23 — CLAUDE.md and PLAN.md created as the cross-session memory for this repo.
- 2026-08-23 — Learning code lives in `g1_vision_teleop/` (the actual git repo) as siblings to
  `g1_teleop`, not the unversioned outer folder. Reason: importability + version control.
- 2026-08-23 — Recorder logs `data.ctrl[12:29]` from the physics model as the action, not twin
  `qpos`. Reason: under box load the two diverge; the policy must learn what was commanded.
- 2026-08-23 — Plain ACT added as a third condition (D8). Reason: without it, an ACT-LSTM-vs-BC
  gap cannot be attributed to the LSTM rather than to action chunking.
- 2026-08-23 (Q1) — Gripper = one slide joint + one `<position>` actuator + one high-friction pad
  per hand. Reason: gives the 0–1 command physical meaning and decouples press force from arm IK,
  so the arm holds a clean pose instead of corrupting the 14 arm dims it is recorded into.
- 2026-08-23 (Q2) — Pelvis-velocity trigger abandoned; `KeyboardCommand` is the demonstration
  interface (TR1). `locomotion_input.py` is **kept** as the §3.3.4 negative-result evidence.
- 2026-08-23 (Q3) — Record and run the policy at **25 Hz**; locomotion inner loop stays 50 Hz.
- 2026-08-23 (Q4) — `d_place = 0.10 m` XY box-to-goal, **and** the box resting upright on the
  goal platform. Reason: 0.06 m would floor place-success for all three policies.
- 2026-08-23 (Q5) — Waist pinned at 0 (D10); dims kept as constants to match Tables 3.3/3.4.
- Full rationale for Q1–Q5 in `NOTES.md`.

---

## 2026-09-08 - O2 RE-MEASURED: the creep number was a rig artifact

Three rigs were built this session. All three earlier grip numbers are withdrawn.

### What was wrong with each

**The 6.2 mm/s creep (previous session).** Measured with the robot on straight
KEYFRAME legs, feet loaded on the floor. That is a pose the locomotion policy
cannot even start from (TR5). It is also the *only* configuration in which the
grasp holds - see the coupling result below.

**The 64 mm "seating slip" (earlier this session).** The box was placed at its
seeded world XY, which is directly over the pickup platform. A slipping box
simply lands back on the platform at z = 0.75 + 0.09 = 0.84. Measured settle
value: **0.8396**. It was a platform landing, not a grasp seating. The tell was
the same as TR11: total insensitivity to every lever - press force 10 -> 200 N
and pad size 70x70 -> 140x140 mm all gave 63.4-65.2 mm.

**The 40 N "verified" contact force.** Same cause: the pads were squeezing a box
the platform was holding up.

### The coupling result — why none of these numbers are gripper properties

Holding behaviour flips on the presence of EIGHT UNRELATED FOOT-FLOOR CONTACTS,
at essentially identical normal force:

| configuration | floor contacts | Fn | box drop |
|---|---|---|---|
| keyframe legs, floor on | 8 | 40.08 N | **18.7 mm** |
| keyframe legs, floor off | 0 | 39.83 N | **150.8 mm** |
| DEFAULT_ANGLES, base pinned at 0.79 | 0 | 39.83 N | **150.8 mm** |

Crouching with the base pinned at 0.79 lifts the feet clear of the floor, which
is why the second and third rows match. Adding eight constraints elsewhere in
the scene changes the contact solution at the grasp by a factor of eight in
slip, with the normal force unchanged to 0.6%. That is solver coupling, not
contact mechanics, and it means no grip number from this model is trustworthy
without stating the whole-body configuration it was measured in.

### The representative rig, and what it says

Correct configuration: legs at DEFAULT_ANGLES **with the feet actually loaded** -
reached by letting the robot settle onto the floor under gravity with the legs
PD-held, then freezing it (gravcomp + pin at the settled pose). Box in mid-air
away from both platforms. Displacement measured in the hand frame.

Grasp quality vs standoff, 3 seeds each, pass = slip < 74 mm (the full-contact
budget from the pad/box geometry):

| reach m | 0.20 | 0.22 | 0.24 | 0.26 | 0.28 | 0.30 | 0.32 | 0.34 | 0.36 |
|---|---|---|---|---|---|---|---|---|---|
| IK residual mm | 68.6 | 62.3 | 55.7 | 48.6 | 41.2 | 33.3 | 25.6 | 18.0 | 12.0 |
| Fn N | 28.7 | 0.2 | 23.3 | 0.6 | 14.4 | 19.9 | 23.2 | 24.4 | 24.8 |
| slip mm | **-2.0** | -676 | -64.1 | -677 | -117.6 | -111.8 | -110.5 | -108.6 | -105.6 |
| pass | 3/3 | 0/3 | 3/3 | 0/3 | 0/3 | 0/3 | 0/3 | 0/3 | 0/3 |

**Success does not track the IK residual.** The single good grasp (2.0 mm slip)
is at reach 0.20, which has the WORST residual (68.6 mm). Reaches 0.22 and 0.26
fail outright while 0.20 and 0.24 succeed - non-monotonic, which no geometric
explanation supports. So narrowing the demonstrator's standoff band is NOT the
fix; the hypothesis that failures come from residual-induced palm misplacement is
not supported.

### Gradual vs instantaneous load transfer

An external upward force on the box decaying mg -> 0 over 2 s, so the load
arrives as it would while the arms lift the box off a platform:

| reach | instant slip | gradual slip |
|---|---|---|
| 0.20 | -2.0 mm (3/3) | -2.5 mm (3/3) |
| 0.24 | -64.1 mm (3/3) | -85.5 mm (0/3) |
| 0.28 | -117.6 mm (0/3) | -647 mm (0/3) |
| 0.32 | -110.5 mm (0/3) | -676 mm (0/3) |

Gradual transfer is equal or **worse**, never gentler. The instantaneous-transfer
protocol was not flattering the result, so that hypothesis is closed too.

### Where this leaves O2

The friction grasp as built does not hold the box in the configuration the robot
actually operates in. It holds at exactly one standoff out of nine tested. Press
force and pad geometry were already shown flat (on a contaminated rig, but flat
across a 20x force range, which is not a promising starting point). The remaining
ladder rungs are box mass and the weld - and the weld is the disclosed fallback
CLAUDE.md has carried since 2026-08-23.

This is a scope decision, not a tuning problem, and it belongs to Charles.

---

## 2026-09-08 - Weld adopted (D11), with the friction negative result confirmed

### The confirmation run, and why the earlier "1 of 9" was also wrong

The 1-of-9 figure was produced on a rig that let the robot settle under gravity
with the legs PD-held at DEFAULT_ANGLES. Without the locomotion policy the robot
cannot balance (TR2), so the pelvis **pitched 23.6 deg and drifted 0.285 m**
while the arms were posed on an upright twin. Net effect: the palms sat 130 mm
BELOW the box (palm-to-box 0.186 m against an IK target of 0.09 m) and the pads
were closing on empty space. That figure is withdrawn too.

**Rig v5**, which the confirmed numbers come from: pelvis UPRIGHT, legs at
DEFAULT_ANGLES, base height solved by bisection so the feet just contact the
floor (8 floor contacts), then frozen with gravcomp + pin. Because the pelvis is
upright it matches the twin the arms are posed on, so joint angles transfer
exactly. It carries a **precondition guard**: a trial is scored only if both
palms are within 45 mm of the box-face centre they are meant to be on.

The guard immediately separated two findings every earlier rig had conflated:

| reach m | 0.20 | 0.22 | 0.24 | 0.26 | 0.28 | 0.30 | 0.32 | 0.34 | 0.36 |
|---|---|---|---|---|---|---|---|---|---|
| palm error mm | 69 | 63 | 56 | 49 | 42 | 34 | 26 | 18 | 11 |
| usable | no | no | no | no | yes | yes | yes | yes | yes |

At reach 0.20-0.26 the **4-DOF IK cannot achieve the grasp pose at all** (D2:
four joints per arm, wrists pinned). That is an ARM limitation, not a gripper
one, and it narrows the usable standoff band to roughly **0.28-0.36 m** - which
supersedes `GRASP_MIN = 0.20` as the band a demonstrator should actually use.

### Confirmed result, 12 seeds x 9 standoffs, 15 s hold

| | valid trials | hold |
|---|---|---|
| friction pinch | 60 | **0 / 60** |
| weld | 60 | **60 / 60** |

Friction: the box falls the full 746 mm to the floor in every valid trial. The
earlier "1 of 9" was optimistic because the palms were below the box and the
pads caught it at the extreme end of their stroke.

### Weld hold quality (drift measured against the LEFT HAND, the welded body)

| reach m | 0.28 | 0.30 | 0.32 | 0.34 | 0.36 |
|---|---|---|---|---|---|
| vertical drift mm | -7.8 | -2.6 | +3.7 | +19.0 | +28.6 |
| lateral drift mm | 19.9 | 23.5 | 27.3 | 33.5 | 39.6 |
| engaged | 12/12 | 12/12 | 12/12 | 12/12 | 12/12 |

Residual drift is MuJoCo equality compliance plus arm loading - equality
constraints are soft, and `solref` is already at its 2x-timestep floor. All well
inside the 74 mm full-contact budget and the 0.10 m Q4 placement tolerance.

Measuring against the palm MIDPOINT instead inflates this to 63-120 mm lateral,
because the two arms settle differently under load and the midpoint moves. That
is arm compliance, not grasp slip; the welded body is the correct reference.

### What is NOT evidence for the negative result

**The "press force flat across 20x" and "pad area flat across 4x" sweeps must
not be cited.** Both were run with the box sitting on the pickup platform, so
the platform was carrying the load and no pad parameter could have mattered.
They are evidence of the rig fault, not of friction infeasibility. Citing them
invites exactly the question that exposes them: why would 200 N behave
identically to 10 N?

The defensible evidence is two-legged:
1. the confirmed 0/60 across the usable standoff band on rig v5;
2. the foot-contact coupling experiment - slip changed 8x (18.7 -> 150.8 mm) at
   constant normal force (40.08 -> 39.83 N) when eight UNRELATED foot-floor
   contacts were removed. That one had the box genuinely in mid-air away from
   the platform, and it shows the contact solution here is not determined by the
   contact mechanics alone.

### The weld, as implemented

`scene.xml` carries `<equality><weld name="box_grasp" body1="left_wrist_yaw_link"
body2="box1" active="false">`. One weld, not two: two would over-constrain. The
HAND rather than the pad, because the pad slides on its own joint.

`g1_teleop/grasp.py` holds the trigger. Engagement requires ALL of:

| condition | threshold | why |
|---|---|---|
| gripper command | >= 0.5 | the action dim; 0 released, 1 engaged |
| each palm to box centre | <= 0.16 m | hands actually at the box |
| palms opposed | dot(u_L, u_R) <= -0.50 | on opposite sides, not both on one face |
| palm separation | 0.12-0.30 m | straddling the box, not collapsed or overshot |

Release is unconditional on command < 0.5 - a policy must always be able to let
go. All four quantities are computed from palm site poses and box pose, which
are already in the 47-D state vector, and all are controlled by the policy's own
arm commands. Commanding 1 with the hands in the wrong place does nothing,
exactly as closing a real gripper on empty air does nothing. This is the
difference between a learnable grasp and a magic flag.

`relpose` is written from the live relative transform at the instant of
engagement, so the constraint is already satisfied when it turns on and there is
no jump.

**Pads stand down while welded.** A pad pressing into a rigidly welded box cannot
move it, so contact force just accumulates - measured **123.6 N**, and
insensitive to the pad command because the servo cannot retract within one
timestep. Releasing the weld with that stored force launched the box at 0.44 m/s.
The pad geoms' `contype`/`conaffinity` are therefore zeroed on engage and
restored on release. The geoms are kept: the trigger and the diagnostics need
them before engagement and after release.

### Limitations paragraph — where it goes

Chapter 3.3.6 (gripper method) needs the deviation itself. The thesis
**limitations section** needs the honest version: object attachment during
transport is a kinematic constraint, not simulated friction, so the results
characterise the policy's ability to position and time a grasp, NOT its ability
to maintain one against slip. Grasp robustness is explicitly out of scope and
would have to be re-established before any physical deployment. The supporting
negative result - that a friction pinch does not hold under these constraints -
belongs there too, with the two-legged evidence above.

---

## 2026-09-08 - O14 closed, O15 blocked by arm-reach instability

### O14 - usable standoff band narrowed to 0.28-0.36 m

`GraspConfig.grasp_min` 0.20 -> **0.28**, `grasp_max` 0.34 -> **0.36**, plus
`GraspConfig.assert_standoff()` which refuses any request outside the band. Below
0.28 the 4-DOF IK (D2) does not produce a weak grasp, it produces an arm pose
that never reaches the box: palm error 69/63/56/49 mm at reach 0.20/0.22/0.24/0.26
against a 45 mm guard.

Reachability over a 25x25 grid of the sample region: **0 of 625 positions
unreachable**. But the latitude is thin:

| | value |
|---|---|
| base-x freedom, mean | 73 mm |
| base-x freedom, minimum | **35 mm** |
| worst case, box at x=1.58 | base_x in [1.220, 1.255], standoff in [0.325, 0.360] |

At the far edge of the spawn region the demonstrator has 35 mm of latitude, and
the bottom of the standoff band is cut off by the pelvis/platform limit
(`max_base_x` 1.255). If collection proves frustrating there, shrinking
`pickup_half[0]` 0.08 -> 0.06 buys back ~20 mm at the cost of 4 cm of x-span.

### O15 - the weld is wired, and immediately exposed a bigger problem

Wired into `run_integrated_combined.py`: a `GraspWeld` is constructed at load,
`weld.update(model, data, grasp_cmd)` runs every control tick, `g` toggles the
command, and the overlay shows cmd / WELDED / gated / open.

The live test never reached engagement. **Extending both arms to the grasp pose
topples the robot, with the locomotion policy running and balancing normally.**

| condition | base_z | pitch |
|---|---|---|
| arms static, robot at origin | 0.780 | -1.5 deg |
| arms static, teleported to a 0.30 m standoff | 0.780 | -1.5 deg |
| **arms reaching to the grasp pose** | **0.160 (fallen)** | +22.7 deg |

Standing is fine. Reaching is not. Pitch passes +17 deg during the reach and
exceeds +50 deg before the grasp command is issued.

### It is the POSE, not the transient

| ramp | reach fraction | base_z | final pitch | max pitch | outcome |
|---|---|---|---|---|---|
| 2.5 s | 100% | 0.149 | +68.6 | 86.6 | fell |
| 8.0 s | 100% | 0.517 | +42.1 | 58.3 | on the edge of falling |
| 8.0 s | 50% | 0.774 | +3.3 | 4.4 | stable |
| 8.0 s | 25% | 0.774 | -0.3 | 3.0 | stable |

Slowing the approach from 2.5 s to 8 s does not rescue it - it only makes the
fall slower. At half the reach the robot is entirely stable. So the full
bimanual grasp pose is itself outside what the controller can hold, and no
approach-shaping fixes that.

### Why, and why it was never seen before

CLAUDE.md section 4 already recorded that the robot "carries arm/torso mass the
12-DOF training model did not" - that was written to explain a ~2 cm/s drift.
The same gap has a much larger consequence: the pre-trained policy never saw
arms move, and a full forward bimanual reach shifts the CoM past what it can
compensate. This is distinct from TR2-TR4, which are all about freezing the
gait; this is arm motion disturbing a leg-only controller.

It also explains, retroactively, the very first O2 harness, where the arms could
never be brought to the box. That was read as an IK problem and the rig was
changed; the robot was actually falling over.

It had never been caught because section 13 lists "run_integrated_combined.py
runs end to end" as ASSUMED, never executed - it needs a ZED. The instability has
plausibly been latent in the teleop path from the start.

### The decision this forces

O14 and O15 pull in opposite directions and may be incompatible:
  * O14: the standoff must be **>= 0.28 m**, or the IK cannot place the palms.
  * O15: at a 0.30 m standoff the arms cannot extend to the box without toppling.

The open question is whether ANY standoff satisfies both. That has not been
measured and should be measured before anything else is attempted - a stability
sweep over standoff, reporting IK palm error and max pitch together. If the two
windows do not overlap, this is a scope decision, not a tuning problem, and the
candidate resolutions all change the task:
  * pin or otherwise support the base during manipulation (changes what
    Objective 1 demonstrates);
  * a lower or closer grasp that needs less arm extension (changes the scene);
  * replace or fine-tune the locomotion controller (RL is out of scope, section 1);
  * accept a seated/stationary manipulation task (large scope change).

---

## 2026-09-08 - O16 CORRECTED: the reach does NOT topple the robot

### The correction

O15/TR15 were recorded as "extending the arms to the grasp pose topples the
robot". **That is wrong.** The pose alone is stable. What topples the robot is
the measurement loop I used: re-solving the IK every 25 steps against a
WORLD-ANCHORED box target while the base was already pitching.

Isolation, standoff 0.30, policy running, 10 s hold:

| base | arm target | base_z | max pitch | outcome |
|---|---|---|---|---|
| origin | fixed | 0.776 | 6.2 deg | stood |
| origin | **re-solved** | 0.757 | **27.1 deg** | stood |
| teleported to standoff | fixed | 0.746 | 14.9 deg | stood |
| teleported to standoff | **re-solved** | **0.349** | **70.9 deg** | **FELL** |

Both factors contribute and the fall needs the combination, but the re-solve is
the dominant term: it quadruples pitch at the origin (6.2 -> 27.1) and is what
turns a 14.9 deg lean into a fall.

**The mechanism** is a positive feedback specific to a world-anchored target: the
base pitches slightly, which moves the shoulder forward and down, so holding the
palm at a fixed WORLD point demands a more extreme arm pose, which disturbs the
base further.

**The live teleop path does not have this loop.** `compute_arm_targets` anchors
the target at `robot_shoulder_world` - the LIVE shoulder - so the target moves
with the robot and is self-referential. A scripted grasp or an autonomous policy
aiming at a world-frame box pose does have it, so it matters for Phase 4, but it
is not a property of the arm pose or of the locomotion controller.

### PART A1 - the overlap window is NOT empty

Baseline, waist pinned at 0 (Q5/D10), box 0.84 m, fixed pose commanded, policy
running and balancing, 10 s hold:

| standoff | 0.24 | 0.26 | 0.28 | 0.30 | 0.32 | 0.34 | 0.36 | 0.38 | 0.40 |
|---|---|---|---|---|---|---|---|---|---|
| palm err mm | 56.4 | 49.4 | 42.0 | 34.2 | 26.2 | 18.1 | 11.1 | 10.1 | 16.9 |
| O14 (<=45 mm) | FAIL | FAIL | pass | pass | pass | pass | pass | pass | pass |
| max pitch deg | 3.9 | 4.7 | 5.4 | 6.2 | 7.0 | 7.7 | 8.6 | 9.5 | 10.4 |
| O15 (no fall) | pass | pass | pass | pass | pass | pass | pass | pass | pass |

**The robot falls at no standoff.** Base height holds at ~0.77 throughout and
max pitch never exceeds 10.4 deg. Both criteria pass across **0.28-0.40 m**, a
12 cm window. O14 alone is the binding constraint, exactly as it was before O15
was (incorrectly) raised.

### PART A2 - waist pitch (Q5 pins it at 0; measurement only, not a proposal)

Cells are palm_err_mm / max_pitch_deg; `*` = both criteria pass.

| standoff | wp=-0.52 | wp=-0.26 | wp=0.00 | wp=+0.26 | wp=+0.52 |
|---|---|---|---|---|---|
| 0.24 | 22/9 * | 38/4 * | 56/4 | 74/10 | 89/14 |
| 0.26 | 14/8 * | 30/3 * | 49/5 | 69/11 | 87/14 |
| 0.28 | 13/8 * | 21/3 * | 42/5 * | 63/12 | 83/15 |
| 0.30 | 21/7 * | 13/3 * | 34/6 * | 57/12 | 78/15 |
| 0.32 | 33/7 * | 10/3 * | 26/7 * | 50/13 | 73/16 |
| 0.34 | 50/7 | 16/3 * | 18/8 * | 43/14 * | 67/16 |
| 0.36 | 68/7 | 26/3 * | 11/9 * | 36/14 * | 61/16 |
| 0.38 | 86/7 | 42/3 * | 10/9 * | 29/15 * | 55/17 |
| 0.40 | 104/7 | 60/3 | 17/10 * | 22/15 * | 49/18 |

**Backward lean helps; forward lean hurts** - the opposite of the brief's
expectation. `wp=-0.26` gives the widest window (0.24-0.38) at the lowest pitch
(3 deg) and cuts palm error to 10-42 mm. Forward lean raises palm error at every
standoff and triples pitch.

Likely why: leaning back moves the shoulders BACK, which for a fixed box makes
the required arm extension shorter, and the 4-DOF IK does better at shorter
extension. Forward lean lengthens the required reach. The brief's premise -
forward lean moves the shoulders 12 cm forward and should help reach - is right
about the kinematics but backwards about which direction the IK needs.

### PART A3 - box height (waist 0)

| standoff | h=0.74 | h=0.79 | h=0.84 | h=0.89 | h=0.94 |
|---|---|---|---|---|---|
| 0.24 | 26/4 * | 42/4 * | 56/4 | 68/4 | 77/4 |
| 0.28 | 14/6 * | 27/5 * | 42/5 * | 54/6 | 63/6 |
| 0.32 | 18/7 * | 13/7 * | 26/7 * | 38/7 * | 48/8 |
| 0.36 | 37/9 * | 15/9 * | 11/9 * | 22/9 * | 31/9 * |
| 0.40 | 66/9 | 36/10 * | 17/10 * | 10/11 * | 15/11 * |

Height is an IK-reach lever, not a stability lever: max pitch is flat at 4-11 deg
across every height. **h=0.79 (5 cm lower) passes both criteria across the whole
0.24-0.40 sweep** - the widest span in the grid.

### PART B - why teleop never fell (answered statically, no camera used)

1. **`run_teleop_combined.py` does not step physics and has no locomotion
   policy.** Counts: `mj_step` 0, `mj_forward` 0, `import torch` 0 in both
   `run_teleop.py` and `run_teleop_combined.py`. The only integration anywhere in
   that path is `mj_forward` inside `ik.py`/`robot.py`. Gravity never acts, the
   base is never integrated, so the robot **cannot** fall. It is not comparable
   to the O15 test.
2. **Max commandable extension** = upper 0.2003 + forearm 0.1841 + palm offset
   0.106 = **0.4904 m** palm-from-shoulder. `DEPTH_SCALE=0.6` does NOT cap it:
   `compute_arm_targets` normalises the segment direction after the camera
   rotation, so a pure forward reach normalises to a full-forward unit vector
   (measured: forward component 1.000). DEPTH_SCALE only tilts MIXED directions
   (45 deg forward+side -> forward component 0.514).
3. **No recorded teleop data exists.** Searched `*.npz`, `*.hdf5`, `*.csv`,
   `*.json`, `*.log`, `demonstrations/`, `data/`; only `.vscode/settings.json`.
   `.gitignore` would hide such files but none are present. There is no record of
   what extension any session actually reached.
4. **The grasp pose needs 0.394-0.452 m, i.e. 80-92% of the 0.4904 m maximum.**
   Demanding, but inside the envelope teleop can command.

So the grasp pose is a more extended posture than teleop would casually produce,
but not beyond its reach - and teleop never fell because it has no physics. A new
operating point, not a regression. And per A1 it is one the robot handles.

---

## 2026-09-09 — O17 extension sweep: the attractor never enters the grasp band

**Question asked:** is the ~0.47–0.53 m attractor set by arm extension? If it is, a shallower
grasp pose should pull it down into the 0.28–0.36 m band.

**Framing.** This is a fixed point, not a displacement. The arms are solved to place the palms at
reach `R` from the pelvis; the base then settles at an equilibrium standoff `S*(R)`. The grasp can
only close where `S*(R) ≈ R`. Sweeping `R` and reading `S*` therefore answers the whole question
in one table. `reach_target` was added to `DemoConfig` to decouple commanded arm reach from the
base station-keeping standoff; nothing else in the control path changed.

Seed 0, box at 0.84 m, waist 0, discrete re-solve off. `ext` = palm-from-shoulder distance.

| R | ext | S* | S*−R | palm err mm | max pitch ° | IK ok |
|---|---|---|---|---|---|---|
| 0.06 | 0.348 | 0.305 | 0.245 | 120.2 | — | NO |
| 0.10 | 0.348 | 0.327 | 0.227 | 92.8 | — | NO |
| 0.13 | 0.357 | 0.333 | 0.203 | 87.2 | — | NO |
| 0.16 | 0.366 | 0.365 | 0.205 | 80.1 | 7.2 | NO |
| 0.20 | 0.380 | 0.402 | 0.202 | 69.0 | 9.9 | NO |
| 0.24 | 0.394 | 0.433 | 0.193 | 56.4 | 12.8 | NO |
| 0.28 | 0.409 | 0.466 | 0.186 | 42.0 | 14.6 | yes |
| 0.32 | 0.423 | 0.493 | 0.173 | 26.2 | 15.2 | yes |
| 0.36 | 0.438 | 0.521 | 0.161 | 11.1 | 16.5 | yes |
| 0.40 | 0.452 | 0.550 | 0.150 | 16.9 | 17.5 | yes |
| 0.44 | 0.461 | 0.574 | 0.134 | 42.5 | 18.7 | yes |
| 0.48 | 0.460 | 0.585 | 0.105 | 77.8 | 20.0 | NO |

**1. The attractor moves monotonically with extension.** `S*` rises smoothly from 0.305 to 0.585
as `R` goes 0.06 → 0.48. It is genuinely set by arm extension — the hypothesis was right.

**2. It converges but never converges far enough.** `S*−R` narrows monotonically from 0.245 to
0.105, so `dS*/dR < 1` and the fixed point is approached from one side only. Extrapolating the
gap linearly, closure would need `R ≈ 0.7 m` — roughly 50% beyond the 0.4904 m maximum commandable
palm-from-shoulder extension.

**3. Extension saturates before the gap closes.** `ext` climbs 0.348 → 0.461 over R = 0.06 → 0.44
and then *stops* (0.460 at R = 0.48). Past R ≈ 0.44 the IK cannot lengthen the arm further, so
commanding more reach only degrades the palm placement — palm error turns around at R = 0.36
(11.1 mm) and rises to 77.8 mm by R = 0.48. The gap keeps narrowing there only because the base
keeps receding, not because the palms get closer to the box.

**4. The band is entered only where the IK has already failed.** `S*` is inside 0.28–0.36 at
R = 0.06, 0.10 and 0.13 — but palm error at those rows is 87–120 mm, two to three times the 45 mm
O14 guard. The arms are barely extended; the base sits close because there is nothing to lean
away from. There is no row where `S*` is in the band *and* the palms are on the box.

**5. The weld gate never fires at any reach.** Running the full episode with `reach_target` set
independently of the standoff, the geometric trigger (palm ≤ 0.16 m from the box centre) fails at
every point where the gap is smallest:

| reach R | standoff at GRASP | predicted palm offset | palm err mm | engaged |
|---|---|---|---|---|
| 0.40 | 0.558 | 0.182 | 16.9 | no |
| 0.44 | 0.582 | 0.168 | 42.5 | no |
| 0.46 | 0.593 | 0.161 | 60.0 | no |
| 0.48 | 0.598 | 0.148 | 77.8 | no |

R = 0.48 is the only row whose predicted offset clears the 0.16 m proximity threshold, and there
the palm error is 77.8 mm — the arms are nowhere near the box, they are simply extended past it in
a pose the IK could not solve. No configuration both closes the gate and places the palms.

**Conclusion.** The attractor does not enter the 0.28–0.36 m band at any extension where the IK
still places the palms. Extension is the right lever and it has been swept to saturation. This
closes the tuning space for a *stationary* bimanual grasp: no combination of grasp depth, lift
height, or commanded reach makes the standing robot's equilibrium standoff coincide with the
standoff its arms can serve. Box height and waist pitch were measured earlier as independent
levers and are far too small (6.9 mm and 28 mm respectively, against a 35–75 mm requirement).

Withdrawn framing: the 151 mm "reach-induced recession" was described as a disturbance to
anticipate with a feedforward pre-position. That is wrong — it is an attractor, so pre-positioning
is rejected by the same dynamics that produced the recession. Feedforward fits only 16–41% of the
sample range against `max_base_x = 1.255` and does not survive contact with the fixed point.

---

## Action vector — per-dimension detail (moved out of CLAUDE.md §6, 2026-09-09)

**Action — 22-D (proposal Table 3.4):** left arm 7 + right arm 7 + waist 3 + left gripper 1 +
right gripper 1 + walking velocity 3.
- The 17 joint-target dims go to `ctrl[ModelIndex.upper_ctrl]`. **Log `data.ctrl`, not twin
  qpos** — equal at write time, divergent under load. Never hardcode the offset (§12).
- The 2 gripper dims are the **weld command** (D11): 0 = released, 1 = engaged, gated on the
  geometric preconditions in `g1_teleop/grasp.py` (palm ≤0.16 m from the box, opposition ≤ −0.50,
  separation 0.12–0.30 m) — so the command alone does nothing.
- The 3 velocity dims go to the locomotion policy, body frame (vx, vy, wz), clipped to
  (±0.80, ±0.40, ±0.80). Source is `KeyboardCommand` (D6).
- Only 8 of 14 arm dims vary (wrists pinned) and the 3 waist dims are constant (D10). Harmless
  for training, but must be disclosed in the thesis.

---

## 2026-09-09 — Platform height swept (0.75–0.90). No window. Base support is now the decision.

**Question:** `max_base_x = 1.255` is set by the pelvis hitting the platform, which is a function
of platform HEIGHT. A taller platform should let the robot stand closer, shortening the required
arm extension, which by the O17 mechanism should pull the attractor in. Constraint: box centre
below ~1.0 m, so the pickup stays a plausible human-scale table posture (G1 shoulder is at a
measured **1.082 m**).

Platform height is changed via `model.body_pos`, not the XML — nothing on disk was touched.

### 1. A taller platform does NOT buy base latitude — past 0.85 it costs it

Collision sweep, 2.5 mm steps, robot in the operating posture (arms at the R = 0.36 grasp pose):

| platform top | box centre | max_base_x | min standoff | first contact |
|---|---|---|---|---|
| 0.75 | 0.84 | 1.247 | 0.253 | **pelvis** |
| 0.80 | 0.89 | **1.257** | 0.243 | **pelvis** |
| 0.85 | 0.94 | 1.247 | 0.253 | **torso_link** |
| 0.90 | 0.99 | **1.125** | 0.375 | **left_elbow_link** |

The premise held only for 10 mm and only up to 0.80. The platform is a thin 40 mm slab, so it
only blocks geoms whose z-span crosses it; raising it walks that band up the robot's forward
profile. The pelvis reaches 0.055 m forward of the base, but `torso_link` reaches 0.15–0.21 m and
the extended elbow further still. At 0.90 the limiter is the robot's own reaching arm and
`max_base_x` collapses by **122 mm** — the opposite of the intent.

### 2. The attractor *appears* to close at 0.85–0.90, but the robot is leaning on the table

S*(R) with the platform raised (same harness as the O17 sweep; `ext` = palm-from-shoulder):

| top | R=0.32 | R=0.36 | R=0.40 | R=0.44 |
|---|---|---|---|---|
| 0.75 | S* 0.473 (gap .153) | 0.499 (.139) | 0.535 (.135) | 0.553 (.113) |
| 0.80 | 0.489 (.169) | 0.520 (.160) | 0.542 (.142) | 0.577 (.137) |
| 0.85 | 0.360 (.040) | 0.477 (.117) | 0.509 (.109) | 0.541 (.101) |
| 0.90 | 0.325 (.005) | **0.359 (−0.001)** | 0.410 (.010) | 0.465 (.025) |

Extension does fall with height exactly as predicted (at R = 0.36: 0.438 → 0.424 → 0.412 →
0.402 m), and at 0.90 the gap closes to zero. **It is not a fixed point.** Two tells:

- At 0.90 the collision sweep says the closest the robot can stand is **0.375**, yet S* reads
  **0.325–0.359**. A free-standing robot cannot settle inside its own collision limit.
- Instrumenting the 5 s hold: the robot is in contact with the platform **100% of every hold**,
  at every raised height, carrying **60–130 N** through `left/right_elbow_link`,
  `*_shoulder_yaw_link` and `*_wrist_roll_link`. It is resting its forearms on the table.

The elbow rides up onto the top *surface* instead of jamming into the near edge, which is why the
dynamic run gets closer than the static sweep allows. This is TR14's signature — a number that
looks good because something other than the intended mechanism is carrying the load.

### 3. The decisive test: the weld gate fires at NO height

The palm-error column in the O17 sweep is the **IK residual on the kinematic twin**, not the
achieved palm position. `GraspWeld.conditions()` on the settled physics state, grip commanded 1,
best moment of a 5 s hold (needs both palms ≤160 mm from the box centre, opposition ≤ −0.50,
separation 120–300 mm):

| platform top | best palm distance | separation | opposition | near | straddle | GATE |
|---|---|---|---|---|---|---|
| 0.75 | 257.8 mm | 200 mm | **+0.69** | no | yes | **no** |
| 0.80 | 254.2 mm | 192 mm | **+0.70** | no | yes | **no** |
| 0.85 | 248.8 mm | 205 mm | **+0.65** | no | yes | **no** |
| 0.90 | **227.3 mm** | 194 mm | **+0.60** | no | yes | **no** |

Two independent failures, not one. Distance is 227–264 mm against a 160 mm threshold. And
opposition is **positive** at every height — the required value is ≤ −0.50, so the palms are not
straddling the box at all, they are both on the near side of it, short of the target. The hands
never arrive; separation passes only because the two hands keep the right spacing *while both
falling short together*.

Height does help, monotonically: best palm distance improves 257.8 → 227.3 mm across the whole
0.15 m rise. That is **30 mm of palm for 150 mm of platform**, and 67 mm is still needed to reach
the proximity threshold alone — implying roughly another 0.35 m of platform, a box centre near
1.34 m, some 0.26 m ABOVE the robot's shoulder. Far outside any defensible pickup posture, and it
would not fix the opposition failure regardless.

### Conclusion

**No platform height in the plausible range (box centre ≤ 1.0 m) opens a window.** The lever
works in the direction predicted and is an order of magnitude too weak, and past 0.85 m it
reverses by making the reaching arm the collision limiter. The apparent closure at 0.90 m is the
robot propping itself on the table, not a reachable grasp.

This closes the last free-base option. Every remaining path requires supporting the base during
manipulation, or otherwise changing scope (walk-in, box brought to the robot, redefined grasp).

---

## 2026-09-09 — D12 base support built; Phase 1 exit gate 10/10 (stationary)

Decision taken by Charles after O17/TR16 closed every free-base lever: constrain
the base during manipulation, release it for locomotion.

### What was built

- `scene.xml` — a second equality, `<weld name="base_lock" body1="world" body2="pelvis">`,
  inactive by default, stiffer than the grasp weld (`solref 0.002`, `solimp 0.99 0.999`).
- `g1_teleop/base_lock.py` — `BaseLock.lock/release/reaction`. `lock()` writes the
  relpose from the live pelvis pose, so the constraint is satisfied at the instant it
  activates and the base does not jump.
- `g1_data/scripted_demo.py` — lock and release are **phase transitions**, declared once
  as `LOCKED_PHASES = {REACH, REPOSITION, APPROACH, GRASP, LIFT, MOVE, LOWER, RELEASE}`.
  The lock goes on entering the first phase in the set and comes off entering the first
  phase outside it. `MOVE` is in the set only for the stationary variant; the walking
  variant removes it, which is why this is a set and not a pair of names. **VERIFY is
  deliberately outside it**, so the episode ends with the base handed back to the
  locomotion policy and an unholdable pose shows up as a fall in scoring.

### The constraint does not fight the policy: the policy stops

While locked the locomotion policy is **not queried** and the legs are PD-held at
`DEFAULT_ANGLES`. Reasons, in order: the policy IS the balance controller (TR2) and there
is nothing to balance once the pelvis is welded; its in-place march would only scrub the
feet against a base that cannot respond; and it would be driven by observations
(near-zero base angular velocity, perfectly upright gravity) it never saw in training,
which is TR3's failure mode. The alternative — a soft hold the policy could tolerate —
was rejected because any compliance reappears as standoff drift, and standoff drift is
the thing the lock exists to remove. Holding the legs at `DEFAULT_ANGLES` rather than at
their mid-march pose is what makes the release safe (TR5): it hands back the exact
configuration the policy expects. On release the LSTM is zeroed, as at episode start.

### Three bugs this work exposed

**1. `eq_data` anchor frame — affects `grasp.py`, and it was live.** MuJoCo's weld
`anchor` is the weld point in **body2's own frame**; `relpose` is body2's pose relative
to body1. `GraspWeld.engage` was writing the anchor as the box origin expressed in the
*hand's* frame — a point ~160 mm outside the box — so the solver yanked the box to
satisfy it. Measured as a one-off **147 mm jump at engage**, after which the weld held
rigidly at the displaced offset. That is the residue behind the D11 "drift <= 29 mm"
figure. Fixed by writing `anchor = 0`. Verified by comparing the achieved box-in-hand
offset against the weld's own stored `relpose`:

| | before | after |
|---|---|---|
| carry drift (LIFT+MOVE) | 147.2 mm | **0.26 mm** |
| achieved vs relpose | 159.6 mm | **0.000 mm** |
| placement error, seed 0 | 0.091 m | **0.056 m** |

The same convention was measured independently for the base lock: anchor in world
coordinates drives the pelvis 789 mm into the floor; anchor = 0 holds it to 0.004 mm
over 500 steps.

**2. The reach path swept the hands through the platform slab.** Interpolating in joint
space straight from the home pose to the grasp pose takes the hands *under* the 40 mm
slab and up through it. Measured: wrists wedged under the near edge at 100 N, both
shoulder position servos saturated against their +-25 N*m limit (demanding 222 N*m) and
both wrist-pitch servos against +-5 N*m (demanding 384 N*m), leaving the palms **183 mm
below the box**. Gravity was never the issue — the required gravity torque at that pose
is 0.26 N*m at the shoulder. Fixed with a staged path: raise close to the body
(`stage_x` 0.10 m, ahead of the platform edge at ~0.12 m), extend forward above the box,
descend beside it wider than it, then close. The withdrawal reverses the same way, and
must rise before returning — sweeping straight back crosses the placed box's y range at
box height and knocked it 145 mm off the platform.

**3. The pads were being driven into the welded box.** `d.ctrl[pad_ctrl]` was set from
the gripper command, extending the pads 0.10 m into a box whose contact is disabled while
welded; `GraspWeld.release` then restored that contact with the pads buried inside it and
ejected the box. Per D11 the pads are detection-only and the trigger is purely geometric,
so they now stay retracted throughout.

### The gate, verified the way TR16 requires

Gated on `GraspWeld.conditions()` against **settled physics state**, not the twin IK
residual, and every non-foot contact on the robot logged through APPROACH/GRASP/LIFT.

| seed | ok | place err m | carry drift mm | weld viol mm | tilt deg | max pitch deg | lock N | base z after release |
|---|---|---|---|---|---|---|---|---|
| 0 | PASS | 0.0564 | 0.26 | 0.032 | 0.00 | 2.9 | 144 | 0.776 |
| 1 | PASS | 0.0907 | 0.16 | 0.021 | 0.00 | 2.9 | 144 | 0.776 |
| 2 | PASS | 0.0564 | 0.26 | 0.032 | 0.00 | 2.9 | 144 | 0.776 |
| 3 | PASS | 0.0564 | 0.26 | 0.032 | 0.00 | 2.9 | 144 | 0.776 |
| 4 | PASS | 0.0885 | 0.15 | 0.021 | 0.00 | 3.0 | 177 | 0.776 |
| 5 | PASS | 0.0907 | 0.16 | 0.021 | 0.00 | 2.9 | 144 | 0.776 |
| 6 | PASS | 0.0564 | 0.26 | 0.032 | 0.00 | 2.9 | 144 | 0.776 |
| 7 | PASS | 0.0907 | 0.16 | 0.021 | 0.00 | 2.9 | 144 | 0.776 |
| 8 | PASS | 0.0907 | 0.16 | 0.021 | 0.00 | 2.9 | 144 | 0.776 |
| 9 | PASS | 0.0561 | 0.26 | 0.032 | 0.01 | 2.9 | 144 | 0.776 |

**10/10.** Placement error mean 0.073 m, max 0.091 m against the 0.10 m Q4 tolerance;
box resting and upright (tilt <= 0.01 deg) in every episode. Weld fired 10/10 and was
never gate-blocked. Achieved grasp geometry: palms **106/110 mm** from the box centre
(limit 160), separation **214 mm** (band 120-300), opposition **-0.961** (limit <= -0.50)
— near/straddle/opposite all true. **No unintended support: zero contact force through
any arm or torso link in any seed.** Zero falls during the episode and zero after release.

An earlier run scored 7/10. All three failures were `PLACE(xy)` with tilt 180 deg — the
box on the floor, upside down. Cause was task geometry, not control: a fixed `place_dy` of
+0.20 m carries the box past the platform's 0.32 m y half-extent for any spawn with
y >~ 0.12. The demonstrator now places **toward the platform's centre line**
(`place_shift = -place_dy if box_y > 0 else +place_dy`), with a load-time assertion that
the target stays on the platform. The displacement is still 0.20 m, twice the Q4
tolerance, so "did not move the box" still fails.

### What the locked base costs

The weld carries a **median 144 N** through the hold (177 N worst seed). Robot mass is
33.44 kg, so body weight is **328 N**: the lock is supplying **~44% of body weight**, with
a 902 N transient at the lock edge and 157 N*m of torque. That is genuine external
support, not a nudge, and the thesis must say so plainly.

Against that: the robot is **not** left in a pose it could not hold. Max pitch is 2.9-3.0
deg while locked, and when the base is released at VERIFY the robot stands and keeps
standing — 0/10 falls, and holding the released state longer changes nothing:

| free-stand after release | 2.5 s | 6.0 s | 10.0 s |
|---|---|---|---|
| fell | no | no | no |
| base z | 0.776 | 0.779 | 0.779 |
| pitch deg | 2.9 | 2.9 | 2.9 |

So the pose is holdable indefinitely. What the free-standing robot cannot do is *stay at
the standoff* while holding it, which is O17 exactly — the lock buys station-keeping, not
posture.

### Caveat that must be disclosed

Per-seed numbers are nearly identical because the stationary variant places the base at a
fixed standoff **relative to the sampled box**, which cancels the spawn randomisation for
everything except the absolute world position. The spawn itself does vary — seed 0
(1.522, -0.097), seed 1 (1.502, 0.189), seed 4 (1.571, 0.005), seed 7 (1.520, 0.167) —
and standoff at lock is 0.333-0.334 m in every case, which is the point: the robot is
teleported to the same relative pose every time. The stationary gate therefore does **not**
exercise spatial variation, and it is not evidence for Objective 4. All 10 seeds were
in-distribution (`heldout` False for every one). Spatial generalisation only becomes a
real test once the robot has to walk in, which is the walking variant (Q7/O12).

---

## State vector, per group (moved out of CLAUDE.md §6, 2026-09-09)

**State — 47-D (proposal Table 3.3):**
| Group | Dim | Source |
|---|---|---|
| box pos / quat | 3 + 4 | `qpos[ModelIndex.box_qpos]` |
| robot base pos / quat | 3 + 4 | `qpos[ModelIndex.base_qpos]` |
| L/R EE pos / quat | (3+4)×2 | `site_xpos`/`site_xmat` of `*_palm_site` (on the hand, not the pad) |
| L/R gripper state | 1 + 1 | weld engaged 0/1, plus `qpos[ModelIndex.pad_qpos]` |
| L/R arm joint angles | 7 + 7 | `data.qpos` of the 14 arm joints |
| waist joint angles | 3 | yaw/roll/pitch — **constant 0**, waist is pinned (D10) |

---

## 2026-09-09 — O18: a fixed base does NOT give Objective 4 enough spatial variation

Question: instead of walking transport, pin the base at a WORLD position and let the
box vary relative to it. How much of the sample region is graspable, and does the Q6
held-out patch fall inside it?

Region x [1.42, 1.58] × y [−0.21, 0.21] = 0.0672 m². Held-out patch x [1.47, 1.53] ×
y [0.04, 0.16]. Grid 5 x-values × 11 y-values = 55 cells. A cell counts as graspable
only if **both** the achieved palm-vs-goal error is ≤45 mm on **settled physics** and
`GraspWeld.conditions()` actually gates.

### Answer: no. ~15% of the region, and the held-out patch is entirely outside it.

| fixed base x | standoff span | stepped coverage | area | held-out patch |
|---|---|---|---|---|
| 1.14 | 0.293–0.453 | **8/55 = 15%** | 0.0098 m² | 0/3 |
| 1.18 | 0.253–0.413 | 7/55 = 13% | 0.0086 m² | 0/3 |
| 1.22 | 0.213–0.373 | 3/55 = 5% | 0.0037 m² | 0/3 |

The graspable cells form a narrow vertical band at **|y| ≲ 0.05 m**. Coverage in x is
fine — the limit is entirely **lateral**, so moving the base in x only trades which x
rows are in range and cannot widen the band. `base_y = 0` is optimal by symmetry: the
pure-kinematics residual map is exactly symmetric in y.

**The Q6 held-out patch (y 0.04–0.16) is outside the covered band in every stepped
configuration tested — 0 of 3 sampled cells.** So a fixed base does not make held-out
box positions meaningful, which was the whole point of the exercise.

### The binding constraint is self-collision, not reach

Pure kinematics (twin IK residual only) says **73–75%** of the region is reachable and
the residual varies smoothly and symmetrically with |y|. Stepped physics says 15%. The
gap is not tracking: it is that **the IK never checks collision**, so a "reachable"
pose can be one the arm cannot physically adopt.

A collision-aware static map — solve the pose, set the stepped model to it, `mj_forward`,
classify — resolves it. Base x 1.14, waist pinned:

```
        -0.210  -0.168  -0.126  -0.084  -0.042   0.000   0.042   0.084   0.126   0.168   0.210
 1.42       S       S       S       S       #       #       #       S       S       S       S
 1.46       S       S       S       S       #       #       #       S       S       S       S
 1.50       S       S       S       S       #       #       #       S       S       S       S
 1.54       R       R       S       S       #       #       #       S       S       R       R
 1.58       R       R       R       R       R       #       R       R       R       R       R
     # feasible 13/55 = 24%    S self-collision 28    R over the 45 mm reach guard 14
```

**Self-collision dominates: 28 of 55 cells.** Confirmed directly in the stepped runs —
`torso_link` and `right_shoulder_yaw_link` in contact at **152–212 N** at (1.50, +0.084)
and (1.46, +0.126).

Mechanism: the grasp holds the palms a fixed 0.18 m apart straddling the box, so for a
box offset to +y the *right* hand must reach across the body centreline, and the right
arm folds into the torso. It is structural to bimanual grasping with a fixed separation
and no torso rotation, not a tuning artifact.

### Waist yaw fixes the pose but not the coverage

Waist yaw is pinned by D10. As a measurement only (D10 unchanged), turning the torso to
face the box, `waist_yaw = gain · atan2(Δy, Δx)`, in the **static** map:

| yaw gain | base 1.10 | base 1.14 | base 1.18 | base 1.22 | self-collisions @1.14 | patch @1.14 |
|---|---|---|---|---|---|---|
| 0.0 (D10) | 18% | **24%** | 22% | 16% | 28 | 1/3 |
| 0.5 | 33% | **42%** | 40% | 27% | 18 | 2/3 |
| 1.0 | 47% | **58%** | 56% | 47% | **1** | **3/3** |

Statically that looks decisive — self-collisions go 28 → 1, coverage 24% → 58%, and the
held-out patch becomes fully feasible. **It does not survive stepped physics.** Base 1.14
with gain 1.0, waist yaw commanded ±0.643 rad, real weld gate: **7/55 = 13%**, held-out
patch **0/3** — no better than pinned. The pass pattern is scattered and non-monotonic in
y, the signature of a transit failure rather than a kinematic one: yaw fixes the *final*
pose but the staged approach path, tuned at y ≈ 0, still fails on the way in.

So there is real headroom between 13% achieved and 24–58% statically feasible, but
capturing it needs a lateral-aware approach path — actual work, not a parameter change.

### Method note

Results are **bit-identical** with `reposition_s` at 0.2 s and 6.0 s, so the shortened
sweep probe is not responsible for any failure. Every non-foot contact was logged per
TR16 trap 2; the palm criterion is the achieved palm-vs-goal distance on settled physics,
never the twin IK residual (TR16 trap 1).

### What was measured vs what was NOT built

Measured only. The walking variant was not built. D10 stands — `waist_yaw` was added to
`DemoConfig` as a measurement knob defaulting to 0, and unpinning the waist remains a
decision D10 owns. `fixed_base`, `box_xy` and `stop_after` were added to `DemoConfig` for
this sweep; the seeded-spawn path used by the recorder is untouched, and the stationary
gate still passes (place error 0.054/0.086 m, drift ≤0.23 mm, no unintended support).

---

## 2026-09-09 — Lateral-aware approach path attempted. NOT ACHIEVED. Root cause found (O19).

Brief: close the 13% achieved vs 58% statically-feasible gap at waist-yaw gain 1.0 by
making the staged approach lateral-aware. **Outcome: coverage did not improve.** Final,
measured with the current code, base (1.14, 0.00), gated on `GraspWeld.conditions()`
against settled physics:

| waist-yaw gain | coverage | static ceiling | held-out patch | box knocked >50 mm |
|---|---|---|---|---|
| 0.0 (D10 pinned) | **8/55 = 15%** | 24% | 0/3 | 11/55 |
| 1.0 (torso to box) | **7/55 = 13%** | 58% | 0/3 | 18/55 |

The stationary gate is preserved at **10/10** throughout.

### 1. Diagnosis — the brief's premise was wrong

The brief assumed the staged path folds the shoulder into the torso for offset boxes.
Walking the whole commanded interpolation statically (every segment sampled, `mj_forward`,
first contact recorded) says otherwise. At gain 1.0, **zero cells fail by self-collision**.
All 33 path contacts are pad-vs-platform during REACH (`left_pad` 17, `right_pad` 12,
`*_wrist_yaw_link` 4). Self-collision was a property of the *final grasp pose* with the
waist pinned, and waist yaw already removes it — that part of the earlier O18 reading was
correct, but it is not what blocks the path.

Contact is also not the discriminator. Stepped, per cell, peak non-foot contact force:
**PASS 55–186 N, FAIL 64–256 N** — overlapping ranges, and `torso_link` is the worst
offender in 6 of 7 passes as well as 46 of 48 fails. It is incidental brushing during the
raise. (Found only after widening the audit: it had covered APPROACH/GRASP/LIFT only, so
REACH-phase contact had been invisible, including in the D12 gate's "no unintended
support" claim. The claim still holds for the phases it covered.)

What actually fails, per class:
- **Reach-limited** (22 cells at gain 1.0): IK residual over the 45 mm guard. Genuine,
  x = 1.58 at base 1.14 is standoff 0.44 m.
- **Box knocked away** (11–18 cells): the approach sweeps the box off the platform.
  Measured at (1.42, −0.084): box ends at (2.159, −0.100, 0.090) — on the floor, 1053 mm
  away, palm error 1039 mm with `opposed` = +0.99 and correct separation. The *hands* were
  fine; the box was gone.
- **Marginal** (rest): palm 55–103 mm against the 45 mm guard, gate firing.

Ruled out by direct measurement: waist-yaw tracking (commanded vs achieved within
0.013 rad at every yaw up to 0.53), arm joint tracking (no joint off by >0.03 rad),
actuator saturation (none), and probe truncation (results **bit-identical** at
`reposition_s` 0.2 s and 6.0 s).

### 2. Root cause (O19): the staging waypoint has never been reachable

`P["up"]` — palms `stage_x` = 0.10 m in front of the pelvis, `approach_h` above the box,
at the wide approach separation — has an **IK residual of 117–218 mm**, five times the
45 mm guard. It is not a pose the arm can adopt, so the reach stage has always been
commanding whatever the IK last produced. At y ≈ 0 the resulting sweep happens to be
benign, which is why the stationary gate passes; off-axis it is not.

Swept to confirm it is not a tuning matter — `up` residual in mm:

| stage_x | sep 0.24 | 0.30 | 0.36 | 0.42 | 0.48 |
|---|---|---|---|---|---|
| 0.06 | 203 | 207 | 213 | 223 | 157 |
| 0.10 | 186 | 180 | 164 | 122 | 122 |
| 0.14 | 126 | 120 | 111 | 111 | 111 |
| 0.20 | 98 | 98 | 97 | 95 | 93 |
| 0.26 | 76 | 76 | 75 | 74 | 72 |

Nothing reaches the guard. A redesign that rises vertically *behind* the platform at the
natural arm separation and then comes in horizontally at box height — which avoids the
slab and the box top entirely — fails the same way: that `raise` waypoint scores 118–176 mm.

**Why:** the home pose puts the palms at (−0.004, ±0.239, −0.173) from the pelvis, and the
IK drives 4 joints per arm with wrists pinned (D2) against a 6-D elbow+wrist task (D3).
Under that formulation the arm cannot place the hands anywhere near the body: the elbow
target from the swivel heuristic is infeasible there. The only reachable waypoints are the
ones out at box height — `side` 16–20 mm and `grasp` 14–21 mm.

So a genuinely lateral-aware path needs a **different IK formulation**, not path tuning.
That is a D2/D3 question, and it is the real blocker.

### 3. What was tried, and what it cost

| change | effect |
|---|---|
| lateral offset carried through the whole pose chain | necessary, kept |
| clearance `approach_h` 0.14 → 0.20 | fixes the knocked-box cells, **drops the stationary gate to 6/10** — reverted |
| continuity seeding, forward from `up` | palm error ~300 mm at cells that passed; **gate 6/10** |
| continuity seeding, anchored at `grasp`, propagating outward | gate back to **10/10**, lateral cells unchanged — kept |
| wider staging separation (0.24 → 0.48) | no improvement, `up` still 72–223 mm |
| rise-behind-then-lane-in redesign | `raise` waypoint 118–176 mm, not reachable |

The two changes that fixed individual cells each regressed the stationary gate. Nothing
beat the 13–15% baseline.

### 4. D10 was NOT reversed, and the brief's reasoning for reversing it does not hold

The brief asked to record unpinning waist yaw as a deviation, on the grounds that turning
the torso removes the centreline crossing behind 28 of 55 failures. **That justification
does not survive stepped physics**: yaw does remove the self-collisions statically (28 → 1,
ceiling 24% → 58%), but achieved coverage goes 15% → **13%**, and the held-out patch stays
0/3. Waist yaw makes the *final pose* feasible and changes nothing about the path, which is
what actually fails.

So no deviation was recorded and D10 stands. `DemoConfig.waist_yaw` remains a measurement
knob defaulting to 0. Reversing D10 should be revisited only if a path is found that
actually converts the static headroom into coverage — at which point the deviation is
worth recording with evidence rather than in advance of it.

### 5. Kept from this session

`build_poses` / `schedule_of` promoted to module level so diagnostics exercise the real
path; anchored continuity seeding in `PoseBook.solve(seed=...)`; the contact audit widened
to every phase; `palm_goal_err_mm` (achieved palm-vs-goal on settled physics, the honest
analogue of the 45 mm guard); `waist_yaw_cmd`/`waist_yaw_achieved`; `trace_every`. All
verified against the stationary gate at **10/10**.

---

## 2026-09-09 — Walking positioning precision. Position is excellent; HEADING is the problem (O21).

Question: if the robot can walk to a stop that puts the box roughly head-on, the
demonstrator only ever needs the head-on grasp it already does at 10/10, and O18/O19
dissolve. Measured over 12 seeded spawns: base starts at (0.60, 0.00), the existing
station-keeping drives it toward `box_xy − [0.32, 0]` for 14 s, then the base locks (D12)
and the staged grasp runs from wherever it stopped.

### Positioning: excellent in position, systematically wrong in heading

| seed | box | standoff m | world lat m | heading ° | settle s | drift mm |
|---|---|---|---|---|---|---|
| 0 | (1.522, −0.097) | 0.3272 | 0.0112 | −17.76 | 1.6 | 24.9 |
| 1 | (1.502, +0.189) | 0.3260 | 0.0120 | −11.67 | 2.3 | 24.8 |
| 2 | (1.462, −0.085) | 0.3276 | 0.0113 | −17.97 | 2.3 | 24.9 |
| 3 | (1.434, −0.111) | 0.3278 | 0.0111 | −18.77 | 2.3 | 24.9 |
| 4 | (1.571, +0.005) | 0.3313 | 0.0080 | −15.05 | 3.1 | 33.8 |
| 5 | (1.549, +0.129) | 0.3267 | 0.0119 | −13.05 | 1.9 | 24.7 |
| 6 | (1.506, −0.066) | 0.3271 | 0.0113 | −17.14 | 1.6 | 24.9 |
| 7 | (1.520, +0.167) | 0.3261 | 0.0119 | −12.37 | 2.3 | 24.8 |
| 8 | (1.472, +0.205) | 0.3260 | 0.0120 | −11.47 | 2.2 | 24.8 |
| 9 | (1.559, −0.090) | 0.3290 | 0.0114 | −17.28 | 2.6 | 26.7 |
| 10 | (1.573, −0.123) | 0.3344 | 0.0045 | −15.48 | 3.1 | 39.2 |
| 11 | (1.441, −0.000) | 0.3273 | 0.0115 | −16.22 | 1.4 | 24.9 |

- **Standoff: 0.3260–0.3344 m, mean 0.3280** — a ±4 mm spread, entirely inside the O14
  band [0.28, 0.36]. Nothing to fix here.
- **World-frame lateral: 4.3–12.0 mm.** Also excellent.
- **Heading: −11.47° to −18.77°, mean −15.35°.** Never near zero, always negative — a
  systematic bias, not noise, and it correlates with lateral travel direction (spawns with
  box y > 0 land at −11 to −13°, y < 0 at −17 to −19°).
- **Settle: 12/12 settled, mean 2.2 s, max 3.1 s** (position error under 20 mm and staying
  under 40 mm).
- **Post-arrival drift: 24.7–39.2 mm** of base wander over the last 4 s. The in-place march
  does keep moving the base, but by tens of mm, not enough to leave the band.

### The heading error is the whole story

The arms work in the **pelvis** frame, so a heading error converts directly into lateral
offset: `effective lateral = −sin(ψ)·Δx + cos(ψ)·Δy`. Computed at the lock instant:

| seed | 0 | 1 | 2 | 3 | 4 | 5 | 6 | 7 | 8 | 9 | 10 | 11 |
|---|---|---|---|---|---|---|---|---|---|---|---|---|
| heading ° | −17.8 | −11.7 | −18.0 | −18.8 | −15.1 | −13.1 | −17.1 | −12.4 | −11.5 | −17.3 | −15.5 | −16.2 |
| **effective lateral mm** | 110 | 78 | 112 | 116 | 94 | 85 | 107 | 81 | 76 | 108 | 93 | 102 |
| palm-vs-goal mm | 62 | 43 | 64 | 65 | 47 | 44 | 60 | 45 | 42 | 65 | 48 | 56 |

**Effective lateral 76–116 mm, mean 97 mm** — an order of magnitude worse than the 11 mm
world-frame number, and well outside the |y| ≲ 50 mm band where head-on grasping works
(O18). The 12 mm of world lateral error is irrelevant next to the ~87 mm contributed by
0.328 m of standoff swung through 15°.

**Correlation between |effective lateral| and palm-vs-goal error: 0.969.** The heading
error is not merely present, it is the mechanism.

### Grasp from where it stopped

Gated on `GraspWeld.conditions()` against settled physics, palm error measured as the
achieved palm-vs-goal distance (not the twin IK residual — TR16 trap 1):

- weld gate fired **12/12** (palms near, straddling, opposed),
- but only **3/12** inside the 45 mm O14 guard; palm errors 42–65 mm.

So the walk-in produces a grasp that engages every time but is out of tolerance three
times in four.

### Why the heading is uncontrolled (O21)

The demonstrator's station-keeper writes `act[0:2]` only — the **wz channel `act[2]` is
never commanded**. The locomotion policy accepts a 3-D body-frame velocity (`cmd_scale`
has three entries, wz scale 0.25) and §6's action vector carries all three, so the channel
exists end to end and simply is not driven. Heading is therefore free to accumulate
whatever bias the policy has while walking laterally, and it does, consistently.

Two consequences worth separating:

1. **The lateral coverage problem does not dissolve, but its size changes.** Head-on
   grasping needs ≲50 mm of effective lateral offset; the walk delivers 97 mm. It is not
   the 210 mm span of the full sample region that O18 was fighting, and it is not a
   coverage problem at all — it is one uncontrolled DOF.
2. **A related frame bug is now documented, not fixed (O20).** `PoseBook.solve` takes a
   pelvis-frame offset and the demonstrator hands it a world-frame delta; the two agree
   only while heading is ~0. Rotating the delta into the pelvis frame is the obvious fix
   and makes things **worse — 10/10 → 3/10** — because the palm separation axis rotates
   with it, taking the palms off the box's faces and onto its corners. A correct fix needs
   `solve` to take a separation *direction*, not a scalar. Left as-is deliberately; the
   comment at `scripted_demo.py` records it.

### Status

Numbers only; nothing proposed and nothing built. The stationary gate is unchanged at
**10/10**. `DemoConfig.start_xy` was added so the base can start away from the box and
walk in, plus a `walk_trace` of base pose during SETTLE; both are measurement-only and the
seeded-spawn path is untouched.

---

## 2026-09-09 — Heading control + O20 separation direction. Walk-in grasp 11/12.

### 1. Heading control (O21 closed)

The station-keeper now drives `act[2]` (wz) as well as `act[0:2]`: desired heading is the
bearing from base to box, error wrapped to (−π, π], `hold_kp_yaw` 2.0, clipped to
±0.60 rad/s (policy tolerates ±0.80), deadband 0.01 rad. It freezes with the rest of the
hold once the grasp is underway, so the welded box cannot drag the heading target.

| | before | after |
|---|---|---|
| heading at settle | −11.5° to −18.8°, mean **−15.35°** | −0.02° to +4.79°, mean **+0.76°** |
| effective lateral | 76–116 mm, mean **97 mm** | 12.7–15.4 mm, mean **13.2 mm** |
| standoff | 0.3260–0.3344 m | 0.3254–0.3276 m |

Effective lateral now sits essentially at the world-frame position error (11–13 mm), which
is what the brief predicted would happen if heading were closed.

**It is a limit cycle, not convergence to zero** — checked because 14 s read −0.01° and
20 s read +2.27°, which would otherwise mean 14 s was a lucky sample. Seed 0, heading vs
time, 2 s windows: mean +1.10 to +1.15°, min −0.10°, max +2.30°, **identical in every
window from t = 4 s to t = 30 s**. Peak-to-peak 2.40°, stationary. The phase within that
cycle is what differs between 14 s and 20 s; the amplitude bounds effective lateral at
≤15 mm either way. That is the gait's own yaw oscillation and it is small enough not to
matter.

### 2. O20 fixed properly: separation DIRECTION, not a scalar

`PoseBook.solve` now takes `sep_dir`, the axis the palms straddle along, in the pelvis
frame; `build_poses` rotates the place displacement along the same axis. At the lock
instant the demonstrator computes both together:

```
offset  = R(-yaw) . (box - pelvis)        # pelvis-frame target
sep_dir = R(-yaw) . y_world = (sin yaw, cos yaw, 0)
```

Both or neither. Rotating the offset alone was the earlier failed attempt (10/10 → 3/10):
it swung the palms onto the box's corners. The elbow swivel preference follows the same
axis, since leaving it on the pelvis y fights the rotated target.

**Stationary gate stays 10/10** — palm 25.2 mm (was 23.9), place error 0.047–0.097 m
against the 0.10 tolerance, carry drift ≤0.25 mm.

### 3. Walk-in grasp, 12 spawns, both fixes live

Settle 14 s, standoff 0.32, gated on `GraspWeld.conditions()` against settled physics:

| seed | standoff m | eff lat mm | heading ° | palm mm | gate | ≤45 mm | place m | task |
|---|---|---|---|---|---|---|---|---|
| 0 | 0.3268 | 12.8 | −0.01 | 35 | yes | PASS | 0.0529 | ok |
| 1 | 0.3268 | 12.7 | −0.02 | 35 | yes | PASS | 0.0923 | ok |
| 2 | 0.3268 | 12.8 | −0.01 | 35 | yes | PASS | 0.0529 | ok |
| 3 | 0.3268 | 12.8 | −0.01 | 35 | yes | PASS | 0.0529 | ok |
| 4 | 0.3254 | 14.7 | +4.46 | 348 | no | over | 0.0930 | ok* |
| 5 | 0.3268 | 12.8 | −0.01 | 35 | yes | PASS | 0.0923 | ok |
| 6 | 0.3268 | 12.8 | −0.01 | 35 | yes | PASS | 0.0529 | ok |
| 7 | 0.3268 | 12.8 | −0.01 | 35 | yes | PASS | 0.0923 | ok |
| 8 | 0.3268 | 12.8 | −0.01 | 35 | yes | PASS | 0.0923 | ok |
| 9 | 0.3268 | 12.8 | −0.01 | 35 | yes | PASS | 0.0534 | ok |
| 10 | 0.3276 | 15.4 | +4.79 | 1132 | no | over | 0.7303 | FAIL |
| 11 | 0.3268 | 12.8 | −0.01 | 35 | yes | PASS | 0.0529 | ok |

**Gate 10/12. Within the 45 mm guard 10/12** (35 mm on each). **Full task 11/12, zero
falls.** (*seed 4's weld engaged after GRASP, during LIFT, so the task completed despite
the GRASP-window palm error.)

### The two failures are the `max_base_x` limit, not heading

Seeds 4 and 10 have box x = 1.571 / 1.573, so their target base x is 1.251 / 1.253 against
`max_base_x` **1.255** — pressed against the pelvis/platform collision limit. That is also
why they alone keep a heading bias: seed 10 sits at mean +5.29° with 33 mm position error
that never converges (stationary from t = 4 s, peak-to-peak 4.33°), because it is jammed.

Backing the standoff off frees the jam and confirms the mechanism:

| seed | standoff | target base x | heading ° | eff lat mm | palm mm | task |
|---|---|---|---|---|---|---|
| 4 | 0.32 / 0.34 / 0.36 | 1.251 / 1.231 / 1.211 | +4.46 / −0.09 / −0.17 | 14.7 / 13.3 / 13.7 | 348 / 329 / 330 | ok* / FAIL / FAIL |
| 10 | 0.32 / 0.34 / 0.36 | 1.253 / 1.233 / 1.213 | +4.79 / −0.09 / −0.17 | 15.4 / 13.2 / 13.7 | 1132 / 910 / **43** | FAIL / FAIL / **ok** |

Heading is fixed for both by standing further back. Seed 10 then grasps cleanly. **Seed 4
does not** — its palm error stays ~330 mm at every standoff with good heading and 13 mm
effective lateral, which is O19's signature (the unreachable staging waypoint), not a
positioning problem.

### Settle-duration sensitivity, flagged not resolved

At 20 s instead of 14 s the grasp gets slightly better (gate 11/12, within guard 11/12,
palm 32 mm) but the **full task drops to 6/12**: five seeds fail `PLACE(xy)` at
0.105–0.107 m against the 0.10 m tolerance. Placement is sitting right on the tolerance
and small changes in where the walk stops push it over. Not investigated.

### Verdict on O18 and O19

- **O18 can close as NOT-REQUIRED, conditional on adopting walking transport.** With
  walk-in the demonstrator repositions per spawn and only ever performs the head-on grasp
  it already does at 10/10. The lateral offset it must absorb is ≤15 mm, not the ±210 mm
  span O18 was fighting. The 15% fixed-base coverage number stops being the constraint —
  but the reason is that the robot moves, so O18 is superseded rather than solved.
- **O19 cannot close.** Seed 4 still fails with the ~330 mm staging signature at every
  standoff tested, with heading and lateral both good. O19 is no longer the critical path,
  but it is still a live defect and it costs 1 of 12 here.

Also unchanged: the far-x edge of the Q6 sample region (x ≳ 1.57) is unreachable at
standoff 0.32 because the target base position violates `max_base_x`. That is Q6 geometry
(NOTES 2026-09-08), now confirmed to bite in the walking variant.

---

## 2026-09-09 — O22 closed (region trimmed). O23 diagnosed: placement undershoot, not drift.

### O22 — the far sample edge, trimmed

`max_base_x` is 1.255 and the walk-in commits to the nominal 0.32 standoff, so the far
sample edge has to leave the base clear of that limit *with margin* — touching it is not
the same as being able to converge onto it. Measured cliff, sweeping box x at three y
values:

| target base x | 1.180–1.250 | 1.260 |
|---|---|---|
| position error | 14.5–14.6 mm | 44.6–46.3 mm |
| heading | −0.01° | +5.2 to +5.5° |
| palm | 35 mm, gate fires | jams |

At target base x = 1.250 one of three y values still jammed ((1.57, −0.15): 46 mm, +5.39°,
palm 309 mm), so **1.240 is the last edge clean at every y tried** → far box edge 1.56 at
the nominal standoff, i.e. a 15 mm margin under `max_base_x`.

`BoxConfig.pickup_half` x trimmed **0.08 → 0.06**. Region x [1.42, 1.58] → **[1.44, 1.56]**.

- x span 0.16 → 0.12 m, **25% lost**; area 0.0672 → 0.0504 m².
- Held-out patch x [1.47, 1.53] **stays inside**, with 30 mm margin on each side (y margins
  0.250 / 0.050 unchanged). Held-out fraction over 2000 seeds: **14.2%**.
- Chosen over widening the standoff for far spawns so the standoff band stays uniform
  across demonstrations.

`assert_reach_fits` could never have caught this: it checks `grasp_max` (limit 1.615) while
the walk-in commits to the *nominal* standoff. A walk-in guard now lives in
`scripted_demo.run_episode`, where the standoff is actually known.

**Re-run, 12 spawns, trimmed region, 14 s settle: gate 12/12, within the 45 mm guard 12/12
(35 mm every seed), full task 12/12, heading |max| 0.02°.**

### O23 — the placement boundary is a systematic undershoot

Decomposed by snapshotting the box at LOWER, at RELEASE, and at the end:

| | settle 14 s | settle 20 s |
|---|---|---|
| `post_release` (box moves after the hands let go) | **0.0 mm, all 12** | **0.0 mm, all 12** |
| `err@lower` ≈ `err@release` ≈ final error | yes | yes |

So it is **neither transport drift nor release disturbance**. Carry drift is ≤0.26 mm and
the box does not move at all once released. The error is fully present the moment the arm
finishes lowering: **the arm puts the box down short of the target.**

The undershoot is systematic and direction-asymmetric:

| commanded | achieved | undershoot | uncommanded dx |
|---|---|---|---|
| +0.200 m (box y<0) | +0.1584 | **41.6 mm** | +45 mm |
| −0.200 m (box y>0) | −0.1068 | **93.2 mm** | −12 mm |

**It is not the commanded pose.** The IK residuals of the place poses are symmetric —
move 34 mm, lower 40 mm, open 25 mm for *both* shift directions — and a lateral sweep of
the palm target is symmetric to the millimetre (47/35/26/24/23/24/26/35/47 mm at
y = −0.25…+0.25). The asymmetry is in what the arm achieves, not what it is asked for.

The mechanism is the single-hand weld: the box is rigidly attached to **`left_wrist_yaw_link`**,
so the box's motion *is* the left wrist's motion, and carrying it toward −y makes the left
arm adduct across the body. `left_shoulder_roll_joint`'s range is asymmetric —
**[−1.588, +2.252] rad** — narrower adducting than abducting, and the measured undershoot
follows that asymmetry (93 mm across the body vs 42 mm on its own side). No joint is
saturated; it is envelope shape, not a hard limit.

**Why settle duration flips the criterion.** It does not change the placement quality; it
shifts the base pose slightly (standoff 0.3268 → 0.3287, heading −0.01° → +2.27°), which
moves the arm's operating point and the undershoot with it: the −y undershoot goes
93 mm → 106 mm. Since `place_dy` is 0.20 m and the −y undershoot is 93–106 mm, the achieved
displacement is 0.094–0.107 m and the Q4 tolerance is **0.10 m** — the criterion sits
exactly on top of the undershoot. It is not measuring placement accuracy at that point, it
is measuring whether the undershoot happened to land under 100 mm.

Consequence for collection: the discard rate would be set by a 13 mm swing in a systematic
error, which is exactly the unpredictability flagged. The +y-shift seeds sit at 0.0923 m —
passing with 8 mm of margin — and the −y-shift seeds straddle the line.

**Not fixed, and the tolerance was NOT loosened.** Two honest routes, both of which change
what the demonstration means and so are Charles's call: correct the commanded place offset
for the measured undershoot (making the achieved displacement match the intent), or choose
`place_dy` so that the *achieved* displacement clears the tolerance with margin in both
directions rather than the commanded one. The second is a smaller change but concedes that
the arm cannot place where it is told.

---

## 2026-09-09 — O23 route 1 measured INFEASIBLE. Root cause is a self-collision (O24).

Task was: correct the commanded place offset for the measured undershoot so the achieved
displacement matches the intent, after first checking the undershoot is stable.
**The stability check passed; the correction then proved physically impossible in one of
the two directions, so it is implemented but disabled.**

### 1. The undershoot is stable — but only against box position

Trimmed region, both directions, two settle durations:

| settle | +y shift | −y shift |
|---|---|---|
| 14 s | 41.5 mm (41.4–41.6) | 93.1 mm (93.1–93.2) |
| 20 s | 39.1 mm (39.0–39.1) | 106.8 mm (106.7–106.8) |

**Independent of box position** — spread across the whole sample region is 0.1–0.2 mm, and
an isolation test (same box at y = ±0.02, direction forced both ways) gives identical
numbers, so it is the direction of travel, not the spawn. But it **is** pose-dependent:
93.1 → 106.8 mm for a 1.9 mm change in standoff and 2.3° in heading. A hardcoded constant
would not hold, which is why the correction was written to run at solve time instead.

### 2. Why the solve-time correction cannot work

Implemented as: solve the place chain, read what the pose actually displaces, extend the
commanded offset by the shortfall, repeat. It needs the twin to predict physics. It does
not:

| | +0.20 | −0.20 |
|---|---|---|
| physics achieved | 0.1584 | −0.1069 |
| twin wrist body | 0.1307 | −0.1401 |
| twin palm midpoint | 0.1755 | −0.1762 |

Both twin quantities are near-symmetric; physics is strongly asymmetric. The twin cannot
see the asymmetry because **the asymmetry is a collision**, and the IK never checks
collision (TR18).

Running it anyway: the free direction improved (41.6 → 16.8 mm) and the blocked direction
did not (93.1 → 90.7 mm), while uncommanded forward drift got worse (45 → 64 mm).

### 3. Root cause (O24): the trailing arm jams into the torso

At the end of LOWER, the *trailing* arm's shoulder roll fails to track and saturates:

| shift | joint | commanded | achieved | error | actuator force | limit |
|---|---|---|---|---|---|---|
| +0.20 | `right_shoulder_roll` | +0.385 | +0.116 | −0.270 rad | **+134.8 N·m** | ±25 |
| −0.20 | `left_shoulder_roll` | −0.385 | −0.124 | +0.261 rad | **−130.7 N·m** | ±25 |

Neither joint is near its range limit ([−1.588, +2.252] rad). The contact audit names the
obstruction: **`torso_link` against `*_shoulder_yaw_link` at 264 N**. The commanded pose
requires the arm to pass through the torso; physics refuses; the servo saturates at ~5× its
limit; the arm stops short; the box, welded to the wrist, stops with it.

The mechanism is symmetric but the *consequence* is not, because the box is welded to
`left_wrist_yaw_link` alone: moving +y the box follows the free arm, moving −y it follows
the jammed one. That is the entire 41 mm vs 93 mm asymmetry.

### 4. The achievable envelope — the blocked direction saturates

Box at y = +0.05, commanded magnitude swept:

| commanded | −y achieved (blocked) | +y achieved (free) | torso force |
|---|---|---|---|
| 0.10 | 0.0844 | 0.0742 | 208–220 N |
| 0.14 | 0.0960 | 0.1119 | 229–247 N |
| 0.18 | 0.1018 | 0.1505 | 248–271 N |
| 0.20 | 0.1051 | 0.1584 | 278 N |

The blocked direction **asymptotes at ~0.105 m**: doubling the command from 0.10 to 0.20
buys 21 mm and raises torso force from 220 N to 278 N. No commanded value yields 0.20 m.
The free direction tracks with a roughly constant ~26–30 mm offset and *is* correctable.

Note the torso contact is present at **every** magnitude including 0.10 m — the arms press
into the torso throughout the place, it is not something that only appears at large
displacement.

**So route 1 is infeasible as specified.** Applying it only where it works would make the
demonstrator direction-dependent — a bigger dataset problem than the present shortfall,
which is at least roughly symmetric. `place_correct_iters` is therefore **disabled (0)**;
the code and its measurements stay in place for when the collision is fixed.

The tolerance was **not** loosened and `place_dy` was **not** set from the achieved value.

### 5. State with the correction off

| | stationary | walk-in 14 s | walk-in 20 s |
|---|---|---|---|
| gate | — | 12/12 | 12/12 |
| within 45 mm guard | — | 12/12 | 12/12 |
| full task | **10/10** | **12/12** | **7/12** |
| place err mean / max | — | 0.0694 / 0.0923 | 0.0747 / 0.1071 |
| over the 0.10 m limit | — | 0/12 | 5/12 |
| achieved free / blocked | — | 0.167 / 0.110 | 0.172 / 0.094 |

The criterion still flips on settle duration, for exactly the reason now identified: the
blocked direction delivers 0.110 m at 14 s and 0.094 m at 20 s, and the tolerance is
0.100 m. The grasp itself is unaffected — 12/12 on both.

### What would actually fix it

Remove the self-collision, not the number. Two candidates, neither implemented: let the
waist yaw during the place so the torso turns with the box instead of blocking the arm
(reverses D10, and O21's heading control already demonstrates the policy tolerates torso
rotation); or generate the place poses with a collision-aware solve rather than the
collision-blind twin IK — which is the same fix O19 needs, in the same place.

---

## 2026-09-09 — O24 clean envelope measured: ±0.06 m, SMALLER than the Q4 tolerance

First, a correction to the previous report: the 208–278 N torso figure was a
**whole-episode maximum**, so it could have come from the raise/approach (O19) rather than
the place. Re-measured with contact and saturation sampled during **MOVE+LOWER only**, box
at (1.50, 0.00) so both directions are legal on the platform:

| cmd | achieved | shortfall mm | torso N | roll err rad | roll N·m | verdict |
|---|---|---|---|---|---|---|
| +0.04 | 0.0213 | 18.7 | **0.0** | 0.032 | 15.6 | **CLEAN** |
| −0.04 | −0.0448 | −4.8 | **0.0** | 0.035 | 17.2 | **CLEAN** |
| +0.06 | 0.0371 | 22.9 | **0.0** | 0.032 | 16.2 | **CLEAN** |
| −0.06 | −0.0601 | −0.1 | **0.0** | 0.037 | 18.4 | **CLEAN** |
| +0.08 | 0.0509 | 29.1 | 87.6 | 0.054 | 26.9 | torso + saturated |
| −0.08 | −0.0723 | 7.7 | 74.3 | 0.053 | 26.4 | torso + saturated |
| +0.10 | 0.0630 | 37.0 | 134.1 | 0.086 | 42.9 | torso + saturated |
| −0.10 | −0.0806 | 19.4 | 135.2 | 0.084 | 41.9 | torso + saturated |
| +0.12 | 0.0743 | 45.7 | 187.4 | 0.118 | 59.2 | torso + saturated |
| −0.12 | −0.0883 | 31.7 | 190.3 | 0.115 | 57.7 | torso + saturated |
| +0.14 | 0.0909 | 49.1 | 206.8 | 0.155 | 77.4 | torso + saturated |
| −0.14 | −0.0936 | 46.4 | 223.8 | 0.149 | 74.5 | torso + saturated |
| +0.16 | 0.1083 | 51.7 | 217.1 | 0.192 | 96.1 | torso + saturated |
| −0.16 | −0.0972 | 62.8 | 242.0 | 0.185 | 92.6 | torso + saturated |
| +0.20 | 0.1440 | 56.0 | 232.7 | 0.270 | 134.8 | torso + saturated |
| −0.20 | −0.1021 | 97.9 | 266.8 | 0.261 | 130.7 | torso + saturated |

**The clean envelope is ±0.06 m commanded, and the onset is sharp**: 0.06 → 0.08 goes from
zero torso contact to 74–88 N, and from 16–18 N·m of shoulder roll to 26–27 N·m, past the
±25 N·m limit. There is no gradual margin to trade.

**Achieved inside the clean envelope is 0.037–0.060 m.** The + direction still undershoots
~19–23 mm with zero torso contact and no saturation, so that part is IK residual and servo
offset, not collision.

### Viability: NO

The largest displacement clean in both directions is **0.06 m commanded / 0.037 m achieved
in the worse direction**, against a Q4 tolerance of **0.10 m**. Setting the place target
inside the clean envelope would make the commanded move smaller than the tolerance that
defines success, so "did not move the box at all" would pass — precisely the failure
`place_dy = 0.20` was chosen to prevent (2026-08-23, Q1–Q5). The criterion would stop
discriminating.

So the collision has to be addressed, not designed around by shrinking the target.

### A third option the numbers now open up

The 0.20 m lateral arm sweep exists **only because the stationary variant could not walk**.
The proposal's real task carries the box to the goal platform at (1.5, −1.5), 1.5 m away,
which always required locomotion. Walking transport now works (12/12 gate, 12/12 guard,
12/12 full task), so the place could be what the thesis actually describes: hold the box and
walk it to the goal platform, arms static throughout.

That sidesteps O24 rather than engineering around it — the arms never make a large lateral
sweep, so the trailing shoulder never adducts into the torso — and it removes an artificial
lateral place from the demonstrations. It is a scope decision, not a fix, and sits alongside
waist yaw and the collision-aware solve for Charles to choose.

---

## 2026-09-09 — SCOPE CORRECTION: walking place adopted. Phase 1 exit gate MET, 12/12.

Decision by Charles. The 0.20 m lateral arm sweep was an artifact of a stationary variant
that could not walk; it is **retired**. The demonstration is now the task the proposal
describes: grasp at the pickup platform, carry the box to the goal platform at (1.5, −1.5),
lower and release there. Recorded as a **scope correction, not a fix** — O24 does not arise
because the motion that caused it no longer exists.

### Structure

`LOCKED_PHASES_WALKING = LOCKED_PHASES - {MOVE}`. MOVE leaves the locked set, so the base
is handed back to the locomotion policy and the legs carry the box while the arms hold the
lift pose. This is exactly what the phase-set was built for (D12, 2026-09-09: "MOVE is in
the set only for the stationary variant; the walking variant removes it").

- `place_shift = 0` under `walk_place`: no lateral arm motion at all.
- Navigation target during MOVE is the goal standoff `(goal_x − standoff, goal_y)` with the
  heading aimed at the goal. The heading target is explicitly **not** recomputed from the
  box during transport — the box is welded to the hand and travels with the robot, so its
  bearing is meaningless there.
- The base re-locks on entering LOWER and the place chain is **re-solved from the pelvis the
  robot actually walked to**, in that pelvis's frame with its own `sep_dir`. Nothing from
  the pickup solve is reused (TR14(d)).
- Scoring targets the goal platform: `platform_goal_geom` for the resting check, goal centre
  for placement error.

### Exit gate, 12 spawns, both settle durations

| | settle 14 s | settle 20 s |
|---|---|---|
| weld gate fired | **12/12** | **12/12** |
| palm error at grasp | 35.4 mm (all) | 32.1 mm (all) |
| within the 45 mm guard | **12/12** | **12/12** |
| box drift during transport | mean 2.69, max 2.75 mm | mean 2.62, max 2.71 mm |
| placement error at the goal | mean 0.0397, max **0.0486** m | mean 0.0291, max **0.0294** m |
| over the 0.10 m Q4 limit | **0/12** | **0/12** |
| resting + upright | 12/12, tilt 0.00° | 12/12, tilt 0.00° |
| falls (whole episode) | **0** | **0** |
| max pitch | 8.5° | 11.0° |
| **full task** | **12/12** | **12/12** |

**The criterion no longer flips on settle duration.** It passes 12/12 at both, with 51–71 mm
of margin against the tolerance instead of straddling it. That was the point of O23: the
0.10 m limit used to sit exactly on top of a 93–107 mm undershoot; the achieved placement is
now 29–49 mm, less than half the tolerance.

Box drift during transport is **2.5–2.8 mm** over a 1.5 m walk — an order of magnitude larger
than the 0.26 mm stationary figure, as expected from walking, and still negligible.

### Residual undershoot under the real task

It does not disappear, and it biases where the box lands:

| settle | landing dx | landing dy |
|---|---|---|
| 14 s | **+30.6 ± 5.7 mm** | −8.1 ± 23.6 mm |
| 20 s | **+27.6 ± 0.1 mm** | −9.2 ± 0.1 mm |

The box lands consistently **~28–31 mm beyond the goal centre in +x** — i.e. slightly further
from the robot, which approaches from −x — with a small −9 mm lateral component. This is the
same IK-residual-and-servo-offset term measured in the clean envelope (19–23 mm with zero
contact and no saturation); the walking place removes the *collision* part of the undershoot
but not this part.

It is systematic, so **every demonstration will place the box ~30 mm past the nominal
target**, and a policy trained on them will learn that offset. It does not threaten the
criterion — 30 mm against a 100 mm tolerance — but it must be disclosed, and it is worth
noting that success is being scored against a target the demonstrator never exactly hits.
At 20 s the spread is 0.1 mm, so it is a bias, not noise.

### Consequence for O10 (episode cap)

The walking-place episode is **50.1 s = 1253 samples at 25 Hz**. O10's cap is 500 steps
(20 s) with ~750 called defensible. Both are now well short. The cap has to be reset from
this, and the dataset cost per demonstration is ~2.5x what the stationary variant implied.

### Status of the issues

- **O23 CLOSED** — placement no longer sits on the tolerance. The undershoot's collision
  component is gone with the lateral sweep; the residual ~30 mm bias is recorded above.
- **O24 CLOSED as not-applicable** — the trailing arm never adducts across the body, so the
  torso collision does not occur. The ±0.06 m clean-envelope measurement stands as the
  evidence that no lateral sweep could have worked.
- **O19 still open** but no longer on the critical path: the staging waypoint remains
  unreachable (residual 117–218 mm) and the approach still works only because the resulting
  sweep is benign. It cost 1/12 in the fixed-base experiments; it costs 0/12 here.

The retired stationary path is kept behind `walk_place=False` for reference.

---

## 2026-09-09 — Phase 1 consolidation, then cleanup

### Gates re-run, no regressions

| gate | result |
|---|---|
| walk_test physics path (headless equivalent) | PASS — 20 s, min base_z 0.770, drift 47 mm |
| episode reset determinism / seed independence | PASS |
| LSTM reset (`hidden_state`, `cell_state`) | PASS |
| mid-episode reset restores the fingerprint | PASS |
| `assert_spawn_fits` / `_reach_fits` / `_heldout_inside` | PASS |
| 2000-seed spawn region | PASS — x [1.440, 1.560], y ±0.210, held-out 14.2% |
| stationary demonstrator (retired path) | 10/10 |
| walking demonstrator | 12/12, palm 35.4 mm, place 0.0397/0.0486 m, 0 falls |

`walk_test.py` itself was NOT executed — it opens a passive viewer and blocks. A headless
equivalent of its physics path (same policy, PD, station-keeping, arms held) was run
instead. The script as a script remains unverified.

### Cleanup applied

- **Deleted** `prepos_offset` (+ `prepos_clamped`), `reach_target`, `box_height` — sweep
  hooks for TR16/O16/O17, all closed, no remaining users. Behaviour identical: gates re-run
  after deletion.
- **Added** `assert_recordable(demo)` — the recorder's precondition. `box_xy` and
  `stop_after` fail *silently* rather than loudly: `box_xy` overrides the seeded spawn, so
  every episode would log the same box position and Objective 4 would have no spatial
  variation; `stop_after` truncates the schedule, so an episode would be logged without its
  place and release. Neither is visible in the recorded state vector.
- **Fixed** CLAUDE.md §4's sample region (still said x [1.42, 1.58]; the O22 trim made it
  [1.44, 1.56]).
- **Rewrote** `scripted_demo.py`'s module docstring. It still described the stationary
  lateral place as current and said the goal platform "needs walking" as though that were
  out of reach — exactly backwards. Walking is now the default and the docstring says so,
  with the stationary variant documented as retired and why.

### Kept deliberately

Pad bodies/geoms/actuators in `g1.xml` (D11's friction negative result, and `grasp.py` still
stands the pads down during the weld); the stationary place path behind `walk_place=False`
(the 10/10 control the scope correction is measured against); `locomotion_input.py` (D6
evidence). Retiring is not deleting.

### O25 raised

Objective 1 is validated **kinematically only**. Neither teleop entry point has ever run
under stepped physics — `mj_step` count 0, no gravity, no locomotion policy, base never
integrated — and no recorded session data exists anywhere in the repo. The
retargeting → IK → arm-command path is proven to produce *poses*, never *motion a standing
robot can execute*.

O19 applies directly: the 4-DOF pinned-wrist IK cannot place the palms near the body
(residual 117–218 mm at every `stage_x` and separation tried). Human bimanual motion passes
the hands near the torso constantly — bringing a box in toward the chest is the obvious
case — and those poses are unreachable. Under `mj_forward` that degrades silently into a bad
pose; under physics it is precisely what saturated the servos and jammed the arm in O19 and
O24. **Must be validated under stepped physics ahead of the Phase 4 pilot, before collection
begins.** Blocked on hardware (needs a ZED).

---

## 2026-09-10 — Phase 2 constant-dimension audit (measurement only; nothing was changed)

What the recorder will actually see, measured on the Phase 1 exit-gate run before `spec.py`
is written. No project file was modified for this; the demonstrator ran unmodified.

### Method, and why it is not a copy of the demonstrator

`g1_data/scripted_demo.run_episode` was run verbatim over seeds 0–11 with
`DemoConfig(walk_place=True, start_xy=(0.60, 0.00), settle_s=14.0, standoff=0.32)` — the
same configuration as the 2026-09-09 walking gate. Instrumentation is external:
`mujoco.mj_step` is wrapped, and the wrapper reads the live `run_episode` frame. A copy of
the loop would have drifted from the code the gate actually scored; this is that code.

- Every quantity is read from the **stepped** `m`/`d`. The `PoseBook` twin is never touched,
  and no IK residual appears anywhere below (TR16 trap (a)).
- Every index resolves through `ModelIndex`; no literal offsets.
- Palm poses come from `site_xpos`/`site_xmat` of `*_palm_site` after an `mj_kinematics`
  refresh, because before `mj_step` those arrays lag `qpos` by one step. The refresh cannot
  perturb the sim — `mj_step` recomputes them from `qpos` anyway.
- Sampling is every 20th physics step = 25 Hz (D4), taken **before** `mj_step`, so `d.ctrl`
  is the command about to be applied and the state is the one it is applied to.

**The gate reproduces exactly**, which is the evidence the instrumentation is
non-perturbing: 12/12 full task, palm error 35.4 mm on every seed, placement 0.0380–0.0486 m
(2026-09-09: 0.0397 mean / 0.0486 max), carry drift 2.53–2.75 mm, max pitch 8.5°, zero falls.

Vector layouts as recorded: state 47-D in the NOTES "State vector, per group" order; action
22-D as `[left arm 7, right arm 7, waist 3, g_L, g_R, vx, vy, wz]`, the 17 joint dims taken
from `d.ctrl[ix.upper_ctrl]` and re-ordered from the model's waist-first order into the
proposal's arms-first order.

### Table 1 — per-dimension audit

"std within-ep (max)" is the largest per-episode std over the 12 episodes; "std across-ep" is
the std of the 12 per-episode means. They are reported separately because they mean different
things for normalization: a dim can be perfectly constant inside an episode and still differ
between them. The last column is stronger than either — the tick-aligned spread across the 12
episodes, i.e. how far apart the 12 trajectories ever get at the same instant. **Zero there
means the dim is a function of the schedule alone and carries no information about the spawn**,
however much it varies in time.

STATE, 47-D

| # | dim | min | max | std within-ep (max) | std across-ep | max cross-ep spread at a tick | class |
|---|---|---|---|---|---|---|---|
| 0 | `box_px` | 1.3694 | 1.6144 | 4.34e-02 | 2.03e-02 | 2.25e-01 | LIVE |
| 1 | `box_py` | -1.7143 | 0.2047 | 8.34e-01 | 7.38e-02 | 4.80e-01 | LIVE |
| 2 | `box_pz` | 0.8356 | 0.9200 | 1.38e-02 | 1.32e-03 | 6.00e-02 | LIVE |
| 3 | `box_qw` | 0.8378 | 1.0000 | 7.01e-02 | 1.99e-02 | 1.62e-01 | LIVE |
| 4 | `box_qx` | -0.2077 | 0.0583 | 3.59e-02 | 6.04e-03 | 2.08e-01 | LIVE |
| 5 | `box_qy` | -0.2119 | 0.1741 | 3.65e-02 | 3.26e-04 | 2.12e-01 | LIVE |
| 6 | `box_qz` | -0.5445 | 0.0500 | 2.45e-01 | 6.97e-02 | 5.74e-01 | LIVE |
| 7 | `base_px` | 0.5996 | 1.3837 | 1.36e-01 | 1.80e-02 | 2.16e-01 | LIVE |
| 8 | `base_py` | -1.5928 | 0.2422 | 8.25e-01 | 7.18e-02 | 4.22e-01 | LIVE |
| 9 | `base_pz` | 0.7274 | 0.7900 | 6.05e-03 | 4.44e-04 | 3.38e-02 | LIVE |
| 10 | `base_qw` | 0.8411 | 1.0000 | 7.10e-02 | 2.08e-02 | 1.57e-01 | LIVE |
| 11 | `base_qx` | -0.0546 | 0.0678 | 1.72e-02 | 7.75e-04 | 5.01e-02 | LIVE |
| 12 | `base_qy` | -0.0432 | 0.0743 | 3.80e-02 | 2.24e-03 | 6.32e-02 | LIVE |
| 13 | `base_qz` | -0.5396 | 0.0798 | 2.53e-01 | 7.73e-02 | 5.78e-01 | LIVE |
| 14 | `palmL_px` | 0.5958 | 1.7680 | 2.39e-01 | 1.34e-02 | 3.88e-01 | LIVE |
| 15 | `palmL_py` | -1.6134 | 0.4819 | 8.54e-01 | 7.65e-02 | 5.03e-01 | LIVE |
| 16 | `palmL_pz` | 0.5664 | 1.0055 | 1.31e-01 | 1.76e-03 | 2.24e-01 | LIVE |
| 17 | `palmL_qw` | 0.6167 | 0.9838 | 1.01e-01 | 1.88e-02 | 3.43e-01 | LIVE |
| 18 | `palmL_qx` | -0.0387 | 0.3252 | 7.61e-02 | 1.44e-03 | 2.41e-01 | LIVE |
| 19 | `palmL_qy` | -0.2459 | 0.7644 | 3.01e-01 | 1.44e-02 | 8.38e-01 | LIVE |
| 20 | `palmL_qz` | -0.6243 | 0.3387 | 2.83e-01 | 7.03e-02 | 6.28e-01 | LIVE |
| 21 | `palmR_px` | 0.5929 | 1.5890 | 1.93e-01 | 2.75e-02 | 2.47e-01 | LIVE |
| 22 | `palmR_py` | -1.8240 | 0.0968 | 8.01e-01 | 7.12e-02 | 4.68e-01 | LIVE |
| 23 | `palmR_pz` | 0.5605 | 1.0264 | 1.30e-01 | 1.52e-03 | 2.46e-01 | LIVE |
| 24 | `palmR_qw` | 0.6348 | 0.9893 | 1.02e-01 | 1.18e-02 | 3.35e-01 | LIVE |
| 25 | `palmR_qx` | -0.2458 | 0.0210 | 6.17e-02 | 8.66e-03 | 2.08e-01 | LIVE |
| 26 | `palmR_qy` | -0.3199 | 0.7610 | 2.84e-01 | 1.11e-02 | 9.15e-01 | LIVE |
| 27 | `palmR_qz` | -0.4402 | 0.1653 | 2.01e-01 | 6.74e-02 | 5.80e-01 | LIVE |
| 28 | `g_L` (weld 0/1) | 0.0000 | 1.0000 | 4.91e-01 | 0.00e+00 | **0.00e+00** | LIVE, **episode-invariant** |
| 29 | `g_R` (right pad qpos) | -0.0121 | 0.0039 | 7.63e-04 | 1.97e-05 | 1.13e-02 | LIVE (but see below) |
| 30 | `q_left_shoulder_pitch` | -0.3183 | 0.5792 | 2.71e-01 | 1.77e-02 | 8.23e-01 | LIVE |
| 31 | `q_left_shoulder_roll` | -0.1264 | 0.2000 | 8.22e-02 | 2.86e-03 | 1.87e-01 | LIVE |
| 32 | `q_left_shoulder_yaw` | -0.3406 | 0.8235 | 2.22e-01 | 2.86e-03 | 3.48e-01 | LIVE |
| 33 | `q_left_elbow` | -0.6476 | 1.2813 | 5.91e-01 | 3.62e-03 | 4.78e-01 | LIVE |
| 34 | `q_left_wrist_roll` | -0.0000 | 0.3070 | 1.36e-01 | 1.15e-04 | 2.22e-02 | LIVE |
| 35 | `q_left_wrist_pitch` | -0.3926 | 1.4920 | 1.66e-01 | 7.23e-03 | **1.80e+00** | LIVE |
| 36 | `q_left_wrist_yaw` | -0.1818 | 0.6194 | 6.44e-02 | 3.89e-03 | 6.17e-01 | LIVE |
| 37 | `q_right_shoulder_pitch` | -0.6998 | 0.3841 | 2.47e-01 | 1.29e-02 | 5.56e-01 | LIVE |
| 38 | `q_right_shoulder_roll` | -0.2012 | 0.0655 | 7.81e-02 | 1.33e-03 | 1.75e-01 | LIVE |
| 39 | `q_right_shoulder_yaw` | -0.5498 | 0.2700 | 1.68e-01 | 1.67e-02 | 8.20e-01 | LIVE |
| 40 | `q_right_elbow` | -0.6715 | 1.2813 | 5.91e-01 | 1.64e-02 | 5.48e-01 | LIVE |
| 41 | `q_right_wrist_roll` | -0.3069 | 0.0000 | 1.36e-01 | 2.94e-05 | 1.24e-02 | LIVE |
| 42 | `q_right_wrist_pitch` | -0.4376 | 1.5746 | 1.84e-01 | 6.24e-03 | **1.96e+00** | LIVE |
| 43 | `q_right_wrist_yaw` | -0.0618 | 0.0058 | 2.56e-03 | 5.69e-05 | 5.92e-02 | LIVE |
| 44 | `q_waist_yaw` | -0.0222 | 0.0277 | 3.53e-03 | 1.05e-04 | 3.36e-02 | LIVE |
| 45 | `q_waist_roll` | -0.0227 | 0.0280 | 7.45e-03 | 2.83e-04 | 4.05e-02 | LIVE |
| 46 | `q_waist_pitch` | -0.0589 | 0.0399 | 1.39e-02 | 1.90e-04 | 3.72e-02 | LIVE |

**No state dimension is HARD-CONSTANT or NEAR-CONSTANT.** Not one of the 47 has zero
variance — including the three waist dims that §6 and the state-vector table both describe as
"constant 0" (see callout 4). The only state dim with *no cross-episode* information is `g_L`.

ACTION, 22-D

| # | dim | min | max | std within-ep (max) | std across-ep | max cross-ep spread at a tick | class |
|---|---|---|---|---|---|---|---|
| 0 | `a_left_shoulder_pitch` | -0.3256 | 0.5815 | 2.74e-01 | 1.73e-02 | 8.31e-01 | LIVE |
| 1 | `a_left_shoulder_roll` | -0.4105 | 0.2000 | 1.41e-01 | 9.49e-03 | 3.46e-01 | LIVE |
| 2 | `a_left_shoulder_yaw` | -0.3378 | 0.8189 | 2.27e-01 | 2.12e-03 | 3.53e-01 | LIVE |
| 3 | `a_left_elbow` | -0.6506 | 1.2800 | 5.92e-01 | 3.52e-03 | 4.81e-01 | LIVE |
| 4 | `a_left_wrist_roll` | 0.0000 | 0.3000 | 1.36e-01 | 2.78e-17 | **0.00e+00** | LIVE, **episode-invariant** |
| 5 | `a_left_wrist_pitch` | 0.0000 | 0.2000 | 9.04e-02 | 2.78e-17 | **0.00e+00** | LIVE, **episode-invariant** |
| 6 | `a_left_wrist_yaw` | 0.0000 | 0.0000 | 0.00e+00 | 0.00e+00 | 0.00e+00 | **HARD-CONSTANT** |
| 7 | `a_right_shoulder_pitch` | -0.7102 | 0.2913 | 2.51e-01 | 1.30e-02 | 5.61e-01 | LIVE |
| 8 | `a_right_shoulder_roll` | -0.2000 | 0.1876 | 8.98e-02 | 2.01e-03 | 1.76e-01 | LIVE |
| 9 | `a_right_shoulder_yaw` | -0.5495 | 0.2695 | 1.72e-01 | 1.70e-02 | 8.19e-01 | LIVE |
| 10 | `a_right_elbow` | -0.6727 | 1.2800 | 5.93e-01 | 1.65e-02 | 5.48e-01 | LIVE |
| 11 | `a_right_wrist_roll` | -0.3000 | 0.0000 | 1.36e-01 | 2.78e-17 | **0.00e+00** | LIVE, **episode-invariant** |
| 12 | `a_right_wrist_pitch` | 0.0000 | 0.2000 | 9.04e-02 | 2.78e-17 | **0.00e+00** | LIVE, **episode-invariant** |
| 13 | `a_right_wrist_yaw` | 0.0000 | 0.0000 | 0.00e+00 | 0.00e+00 | 0.00e+00 | **HARD-CONSTANT** |
| 14 | `a_waist_yaw` | 0.0000 | 0.0000 | 0.00e+00 | 0.00e+00 | 0.00e+00 | **HARD-CONSTANT** |
| 15 | `a_waist_roll` | 0.0000 | 0.0000 | 0.00e+00 | 0.00e+00 | 0.00e+00 | **HARD-CONSTANT** |
| 16 | `a_waist_pitch` | 0.0000 | 0.0000 | 0.00e+00 | 0.00e+00 | 0.00e+00 | **HARD-CONSTANT** |
| 17 | `a_gL` | 0.0000 | 1.0000 | 4.91e-01 | 0.00e+00 | **0.00e+00** | LIVE, **episode-invariant** |
| 18 | `a_gR` | 0.0000 | 1.0000 | 4.91e-01 | 0.00e+00 | **0.00e+00** | LIVE, **episode-invariant** |
| 19 | `a_vx` | -0.0955 | 0.8000 | 2.07e-01 | 4.31e-02 | 6.59e-01 | LIVE |
| 20 | `a_vy` | -0.8000 | 0.5106 | 3.49e-01 | 8.51e-02 | 9.15e-01 | LIVE |
| 21 | `a_wz` | -0.6000 | 0.6000 | 1.79e-01 | 4.28e-03 | 8.47e-01 | LIVE |

**5 action dims are HARD-CONSTANT at exactly 0** (both wrist yaws, all three waist dims), and
**6 more are episode-invariant** (the four wrist roll/pitch dims are the same time-series in
all 12 episodes, bit for bit; both gripper dims likewise). So **11 of 22 action dims carry no
information about the spawn**, and the 8 shoulder/elbow dims plus the 3 velocity dims are the
whole learnable action. This confirms CLAUDE.md §6's "only 8 of 14 arm dims vary" and extends
it: the 6 wrist dims are not merely low-variance, they are a scripted clock.

### Callout 1 — what `g_L` and `g_R` actually read as

The 47-D spec allots 1+1. The weld is left-hand only and the pads are detection-only, so
there is no symmetric pair to read. What is on the model:

| channel | min | max | std | distinct values |
|---|---|---|---|---|
| weld `eq_active` | 0 | 1 | 0.491 | exactly {0, 1} |
| `pad_qpos` left | -0.00483 | +0.01320 | 9.28e-04 | continuous |
| `pad_qpos` right | -0.01211 | +0.00389 | 6.78e-04 | continuous |

Recorded here as `g_L` = weld bit, `g_R` = right pad qpos, which is the only assignment that
keeps the left/right labels meaning anything. Both readings are degenerate:

- **`g_L` is a clock, not an observation.** It is bit-identical across all 12 episodes — the
  weld engages at the same tick every time, because engagement is driven by the phase schedule
  and the geometric preconditions are met on the first try in every episode (command ≥ 0.5 on
  40.5% of ticks, weld engaged on 40.5% of ticks, **commanded-but-refused on 0.0%**). Nothing
  in the dataset teaches a policy that the gate can refuse.
- **`g_R` contains no grasp signal at all.** The pads are commanded to 0 throughout and their
  contact is disabled while welded (D11), so the channel is passive slide-joint deflection at
  the ±10 mm scale. Point-biserial correlation with the weld state is **−0.072 (left) /
  +0.038 (right)**; while welded its std collapses to 4e-5, while released it is 9e-4 — i.e.
  the only thing it encodes is whether the pad is free to jiggle. It passes the LIVE test
  (std 6.4e-4 > 1e-6) purely on physical noise. Z-score normalization would amplify that noise
  to unit variance and hand the policy a pure-noise input dimension.

### Callout 2 — the two gripper ACTION dims are the same number

`a_gL` and `a_gR` are **bit-identical at every tick of every episode**: max |difference| =
0.0, so the correlation is 1.0 by construction rather than by measurement. The demonstrator
computes a single scalar `cmd` from the phase and passes it to `GraspWeld.update`; there is
no second channel anywhere in the code. Two action dimensions carry one bit.

### Callout 3 — `vy`: CONFIRMED, and worse than stated

The concern is confirmed, and there is a second half to it.

| | scripted demonstrator | `KeyboardCommand` (D6) |
|---|---|---|
| `vy` | continuous, **[−0.800, +0.511]**, nonzero on 99.8% of ticks where the policy is queried | `_clip_cmd(fwd, **0.0**, turn)` — hardcoded 0, always |
| `vx` | continuous, [−0.096, +0.800] | 3-valued: {−0.35, 0, +0.35}, halved in precision mode |
| `wz` | continuous, [−0.600, +0.600] | 3-valued: {−0.25, 0, +0.25} |

`vy` is not incidental: over the ticks where the policy is actually queried, mean |vy| = 0.156
against mean |vx| = 0.131 — **the lateral channel carries more command magnitude than the
forward one**, because the transport leg starts with the robot facing +x and the goal 1.5 m
away in −y. By phase:

| phase | ticks queried | mean \|vy\| | max \|vy\| | ticks \|vy\| > 0.4 |
|---|---|---|---|---|
| SETTLE | 4200 | 0.033 | 0.511 | 0.1% |
| MOVE | 4800 | **0.261** | 0.800 | **30.9%** |
| VERIFY | 756 | 0.167 | 0.734 | 16.7% |
| all others | 0 (base locked) | — | — | — |

So a teleop demonstration cannot reproduce the transport at all — not "with a different
distribution", but with a dimension that is structurally zero. Two consequences to decide,
not decided here: whether scripted and teleop episodes can share one dataset, and whether the
recorder should log the command in effect or a per-source flag.

**Second half — the clip limits in the action-vector spec are wrong for the scripted path.**
NOTES documents the velocity dims as clipped to (±0.80, ±0.40, ±0.80), which is
`locomotion_input._clip_cmd` (`MAX_LATERAL = 0.40`). The demonstrator never calls that
function: it clips `act[0:2]` jointly with its own `hold_max = 0.80` and `act[2]` with
`hold_max_yaw = 0.60`. Measured against the documented limits: **`vy` exceeds ±0.40 on 16.5%
of queried ticks and reaches ±0.80**, while `wz` never exceeds ±0.60. Whatever `spec.py`
declares as the action range must come from this measurement, not from `_clip_cmd`.

### Callout 4 — the waist is constant in the ACTION and live in the STATE

`a_waist_*` are HARD-CONSTANT at exactly 0.0 — D10 holds for the command. The achieved joint
angles are not:

| dim | achieved \|max\| | rms |
|---|---|---|
| `q_waist_yaw` | 0.0277 rad (1.59°) | 0.0030 |
| `q_waist_roll` | 0.0280 rad (1.61°) | 0.0071 |
| `q_waist_pitch` | **0.0589 rad (3.37°)** | 0.0167 |

Small, but not zero and not noise — it is the kp=500 servo deflecting under the arm and box
load, and it varies with the phase. The state-vector table's "waist 3 — **constant 0**" is
therefore true of dims 14–16 of the action and false of dims 44–46 of the state. Worth one
sentence in the thesis rather than a silent 3-dim mismatch.

### Callout 5 — NEW, and not part of the brief: the "pinned" wrists are not pinned

`q_left_wrist_pitch` spans **−0.393 to +1.492 rad** and `q_right_wrist_pitch` **−0.438 to
+1.575**, against action dims that are a bit-identical ramp to 0.200. Cross-episode spread at
a single tick reaches **1.80 / 1.96 rad**. That is a joint the whole IK
formulation (D2) assumes is pinned, moving 80° while its command sits still, so it was
chased down.

**Mechanism, measured (seeds 4 and 0, contact forces and actuator forces sampled at 25 Hz):
both wrists wedge under the pickup platform during the first ~1.4 s of REACH.**

```
t=14.48 REACH  left_wrist_yaw_link|platform_pickup  33 N
t=14.56 REACH  both wrist_yaw_links vs platform      70 N   q_wrist_pitch 0.09 -> rising
t=14.80 REACH  ...                                   60 N   q = 1.04  cmd 0.19  f = -481 N*m
t=15.28 REACH  pads vs platform 5-26 N               q = 1.49 / 1.57  (joint limit 1.614)
t=15.44 REACH  contact clears                        qvel -13.4 rad/s, snaps back
t=15.84 REACH  q back to 0.20                        settled
```

The position actuators have **no forcerange** (`actuator_forcerange = [0, 0]` = unlimited), so
the servo answers a 1.3 rad error with **−692 N·m** and the joint runs to its ±1.614 rad limit
and then snaps back at up to 15 rad/s. Per seed, max |achieved − commanded| during REACH:

| seed | 0 | 1 | 2 | 3 | 4 | 5 | 6 | 7 | 8 | 9 | 10 | 11 |
|---|---|---|---|---|---|---|---|---|---|---|---|---|
| L wrist pitch | 1.05 | 0.00 | 0.71 | 0.52 | 1.30 | 1.16 | 0.97 | 0.00 | 0.00 | 1.24 | 1.29 | 0.56 |
| R wrist pitch | 0.92 | 1.25 | 0.00 | 0.00 | 1.38 | 1.32 | 0.72 | 1.18 | 0.94 | 1.24 | 0.83 | 0.74 |

**12/12 episodes wedge at least one wrist; 8/12 exceed 1.0 rad on at least one.** Ticks per
episode where any upper-body joint is more than 0.1 rad from its command: 44–150, mean 64
(3.5–12.0% of the episode).

This is **TR17's third path bug, still live**: "a joint-space reach interpolation sweeps the
hands *through* the 40 mm platform slab (wrists wedge at 100 N)". The staged approach fixed
the *descent onto the box*; the `home -> P["up"]` segment of REACH still sweeps the wrists
through the platform's near edge. It is also O19's signature in a different place — `P["up"]`
is the waypoint with the 117–218 mm IK residual, and the twin IK never checks collision.

Why the gate never caught it: the gate scores grasp, placement, resting, tilt and falls, and
this transient costs none of them — the arm recovers 1.8 s before the reach ends. The
contact audit inside `run_episode` records `support` but nothing gates on it.

**Why it matters for Phase 2 specifically:** every demonstration will contain a ~1.4 s window
in which four state dims move 1.5 rad with no corresponding action, driven entirely by a
collision. For BC that is state-action pairs where the action does not explain the state; for
ACT/ACT-LSTM it is a chunk boundary the policy is asked to reproduce and cannot. It also
means the dataset teaches the policy to drive its wrists into the table. Raise as a new open
issue (O26 if adopted) — **fixing it is a demonstrator change and belongs before collection,
not after.**

### Callout 6 — where the across-episode variance actually is

| group | within-ep std | across-ep std | ratio |
|---|---|---|---|
| state box pos | 0.2601 | 0.0318 | 0.122 |
| state base pos | 0.2660 | 0.0301 | 0.113 |
| state palm L / R pos | 0.366 / 0.340 | 0.031 / 0.033 | 0.084 / 0.098 |
| state arm joints | 0.1891 | 0.0066 | **0.035** |
| state waist joints | 0.0079 | 0.0002 | 0.024 |
| action arm cmds | 0.1865 | 0.0058 | **0.031** |
| action velocity cmds | 0.1866 | 0.0442 | 0.237 |

The arm commands differ between episodes by ~3% of how much they vary within one. This is the
known consequence of base station-keeping to a *box-relative* standoff (see 2026-09-09, O21):
at the lock instant the standoff is **0.3268 m and the lateral offset +12.7 to +12.8 mm in
all 12 episodes**, and the palm error is 35.4 mm in all 12. The world positions do vary — box
spawn x 1.450–1.555, y −0.123 to +0.205 — and that variation lands in the box/base/palm
*position* dims, which is what Objective 4 is scored on. But **the manipulation itself is one
trajectory repeated 12 times in the pelvis frame**; the spatial variation the policy must
generalize over is carried almost entirely by the locomotion phase. Not a bug — it follows
from D12 plus walking transport — but it is a property of the dataset that belongs in the
thesis, and it should be checked again at 100–150 demonstrations rather than assumed.

Per TR18, the check that this is *not* a rig artifact: the quantities that must vary do vary
(box x/y above; per-episode-mean spread base_px 55 mm, base_py 194 mm, box_py 199 mm), and
the identical ones are identical for a mechanism that is understood and documented.

### Table 2 — the SETTLE dead prefix

Convergence is scored on the demonstrator's own station-keeping error (`hold_target −
base_xy`): first tick under 20 mm that never afterwards exceeds 40 mm — the same criterion as
the 2026-09-09 walking-precision measurement — and, separately, on heading: first tick under
2° of the heading target that never afterwards exceeds 5°. The dead prefix runs from the later
of the two to the end of SETTLE.

| seed | box (x, y) | pos-conv s | heading-conv s | both s | dead s | dead samples | % of episode |
|---|---|---|---|---|---|---|---|
| 0 | (1.516, −0.097) | 1.56 | 1.60 | 1.60 | 12.40 | 310 | 24.7% |
| 1 | (1.501, +0.189) | 2.32 | 1.88 | 2.32 | 11.68 | 292 | 23.3% |
| 2 | (1.471, −0.085) | 1.56 | 1.56 | 1.56 | 12.44 | 311 | 24.8% |
| 3 | (1.450, −0.111) | 1.60 | 1.60 | 1.60 | 12.40 | 310 | 24.7% |
| 4 | (1.553, +0.005) | 1.48 | 0.04 | 1.48 | 12.52 | 313 | 25.0% |
| 5 | (1.537, +0.129) | 1.48 | 0.60 | 1.48 | 12.52 | 313 | 25.0% |
| 6 | (1.505, −0.066) | 1.52 | 1.56 | 1.56 | 12.44 | 311 | 24.8% |
| 7 | (1.515, +0.167) | 2.32 | 1.88 | 2.32 | 11.68 | 292 | 23.3% |
| 8 | (1.479, +0.205) | 2.32 | 1.88 | 2.32 | 11.68 | 292 | 23.3% |
| 9 | (1.544, −0.090) | 1.52 | 1.60 | 1.60 | 12.40 | 310 | 24.7% |
| 10 | (1.555, −0.123) | 1.56 | 1.60 | 1.60 | 12.40 | 310 | 24.7% |
| 11 | (1.455, −0.000) | 1.36 | 0.04 | 1.36 | 12.64 | 316 | 25.2% |

**Convergence 1.36–2.32 s (mean 1.72 s); dead prefix 11.68–12.64 s = 292–316 samples, mean
307 — a quarter of every episode.** The walk itself is 34–58 samples long.

What is in the dead window, measured: the 17 joint action dims are **exactly** constant
(max deviation from tick 0 is 0.0 across all 350 SETTLE ticks, every seed), the box does not
move (0.00 mm), and the base marches in place, wandering 19.5–44.6 mm with 3.3–5.1° of yaw
limit cycle while `vy`/`vx`/`wz` chatter around zero. So the dead prefix is not literally
static — it is 12 s of the locomotion policy holding station with the arms frozen at home,
which is a real behaviour, just not part of the manipulation.

The measurement, not the decision: `settle_s = 14.0` is ~5× longer than needed for the walk-in
it exists to allow. Trimming SETTLE to converged + a small margin removes ~300 samples per
demonstration; leaving it in teaches the policy a 12 s stand-still that a deployed policy has
no way to know it should end.

### Table 3 — samples per episode

| | value |
|---|---|
| min | **1253** |
| max | **1253** |
| mean | **1253.0** |
| episode length | 50.10 s, all 12 |

Identical across all 12 seeds — and this one is **not** a TR18-style artifact: the schedule is
a fixed list of phase durations (`schedule_of`), so the step count is a constant by
construction and cannot depend on the spawn. Nothing adaptive terminates an episode. Per-phase
breakdown (identical for every seed):

| phase | samples | s | | phase | samples | s |
|---|---|---|---|---|---|---|
| SETTLE | 350 | 14.00 | | MOVE | 400 | 16.00 |
| REACH | 75 | 3.00 | | LOWER | 50 | 2.00 |
| REPOSITION | 150 | 6.00 | | RELEASE | 50 | 2.00 |
| APPROACH | 50 | 2.00 | | VERIFY | 63 | 2.52 |
| GRASP | 15 | 0.60 | | | | |
| LIFT | 50 | 2.00 | | **total** | **1253** | **50.10** |

**This is the number O10's cap must be set from: 1253, not 500 and not ~750.** Two riders.
(1) It is a constant only while the schedule is fixed — any adaptive phase termination makes
it a distribution and the cap must then be measured again. (2) 307 of the 1253 are the SETTLE
dead prefix and 15 are GRASP: the phase the task turns on is **1.2% of the dataset**, against
28% for MOVE and 28% for SETTLE. Whatever the cap becomes, the phase balance is the number
that should worry us more than the total.

### Reproduction

Throwaway scripts, scratchpad only, nothing added to the repo: `phase2_record.py` (frame-hook
recorder, writes `ep_XX.npz` + `summary.json`), `phase2_report.py` / `phase2_report2.py`
(tables), `phase2_reach_probe.py` (callout 5). Re-derivable from this section; the raw npz is
not worth keeping.

---

## 2026-09-10 — Base-lock predicate (D12): measurement, then a definition

The scripted demonstrator locks and releases the base on PHASE transitions
(`LOCKED_PHASES_WALKING`). Deployment has no phase machine and neither does
teleoperated collection — the human supplies the trajectory, not a schedule. So
the lock has to fire from an **observable predicate over the 47-D state**, on the
same principle as D11's geometric weld gate: something the policy causes and can
observe. It also has to be the SAME predicate in collection and deployment, or the
demonstrations show lock timings the policy will never see.

This section measures what the four transitions actually look like, proposes a
predicate, and reports how far it would have fired from the scripted transition.
**Nothing was changed** — the demonstrator, CLAUDE.md and `spec.py` are untouched.

### Method

`run_episode` run verbatim over the 12 exit-gate seeds
(`walk_place=True, start_xy=(0.60, 0.00), settle_s=14.0, standoff=0.32`),
instrumented at 25 Hz through the same external `mj_step` hook as the 2026-09-10
constant-dimension audit. 12/12 pass. Every quantity comes from the **stepped**
model (TR14); the 47-D state is built through `g1_data.spec.SpecLayout`, so every
candidate term below is provably derivable from the recorded state vector plus
fixed scene constants. The state-derived grasp geometry was checked against
`GraspWeld.conditions()` on the same ticks: **max difference 5.6e-16** — the weld
gate is exactly reconstructible from the state, as D11 intended.

Lock and release ticks are read from `BaseLock`'s own equality bit, not assumed
from the schedule. All 12 seeds transition at **ticks 350 / 690 / 1090 / 1190**
(LOCK 1 SETTLE→REACH, RELEASE 1 LIFT→MOVE, LOCK 2 MOVE→LOWER, RELEASE 2
RELEASE→VERIFY). Identical because the schedule is a fixed list of durations.

Scene constants used (fixed by Q6/TR13, read from the model, not hardcoded):
pickup (1.5, 0), goal **(1.5, −1.5)**, platform tops **0.75**, box half-extent
0.09, so resting box centre **0.84**.

### What every quantity reads at the four transitions

Range over the 12 seeds. **T** = tight (spread small enough to threshold),
**L** = loose, **A** = tight but ARTIFACT (see below).

| quantity | LOCK 1 | RELEASE 1 | LOCK 2 | RELEASE 2 | verdict |
|---|---|---|---|---|---|
| weld bit | 0 | 1 | 1 | 0 | **T** — the cleanest term there is |
| base→box XY, m | 0.3270 | 0.3318 | 0.3453–0.3485 | 0.2518–0.3313 | A / A / T / L |
| box standoff along heading, m | 0.3267–0.3268 | 0.3318 | 0.3452–0.3485 | 0.2495–0.3310 | **A** at LOCK 1 |
| box lateral in pelvis frame, m | 0.0129–0.0130 | 0.0031–0.0032 | 0.0042–0.0085 | −0.015–0.036 | **A** / A / T / L |
| heading error to box, deg | 2.268–2.287 | 0.533–0.549 | 0.690–1.403 | −2.67–8.06 | **A** / A / T / **L** |
| base→goal standoff along heading, m | 0.272–0.377 | 0.273–0.377 | **0.279–0.299** | 0.279–0.299 | — / — / **T** |
| goal lateral in pelvis frame, m | −1.69..−1.36 | −1.69..−1.36 | **0.005–0.010** | 0.005–0.010 | — / — / **T** |
| heading error to goal, deg | −79.8..−74.7 | −79.8..−74.7 | **1.00–2.01** | 0.96–1.99 | — / — / **T** |
| box above platform top, m | 0.0899 | 0.1514 | 0.0957–0.1068 | 0.0899 | **T** |
| box above resting height, m | −0.0001 | **0.0614** | 0.0057–0.0168 | −0.0001 | **T** |
| box→goal XY, m | 1.378–1.705 | 1.369–1.695 | 0.0496–0.0661 | **0.0380–0.0389** | **T** |
| worst palm→box, m | 0.4770 | 0.1179–0.1180 | 0.1179–0.1180 | **0.328–0.366** | **T** |
| closer palm→box, m | 0.4622 | 0.1022 | 0.1023–0.1024 | 0.129–0.319 | T / T / T / **L** |
| palm separation, m | 0.4759 | 0.2128 | 0.2127–0.2128 | 0.482–0.586 | T |
| palm opposition dot | +0.487 | −0.867 | −0.865..−0.864 | −0.870..−0.638 | T / T / T / L |
| `GraspWeld.conditions()` ok | false | true | true | false | **T** |
| base XY move / 0.80 s, m | 0.0002 | 0.0 (locked) | 0.0011 | 0.0 (locked) | see below |
| pelvis height, m | 0.7748 | 0.7751 | 0.7698–0.7722 | 0.7699–0.7721 | T, uninformative |
| base linear speed, m/s *(NOT in the state)* | 0.1127–0.1128 | 0.0 | 0.032–0.108 | 0.0 | — |
| lock reaction force, N | 0.0 | 0.0 | 0.0 | 0.0 | — |

### Two ways to be fooled, both checked

**1. Most of LOCK 1's tightness is a station-keeper artifact, not a property of
the task.** The box standoff spreads **0.06 mm** across 12 seeds and the heading
error **0.019°**. Nothing physical is that repeatable: the demonstrator drives
`carry.hold_target = box_xy − [standoff, 0]` with a 4 mm deadband, so every
episode converges to the same pelvis-frame geometry by construction (the same
mechanism behind the identical 35.4 mm palm error, NOTES 2026-09-09). **A human
teleoperator will not reproduce it, and a policy at deployment will not either.**
Thresholds below are therefore taken from what the ARMS need — the O14 standoff
band, O18's |lateral| ≲ 0.05 m grasp band — and not fitted to the observed
spread. The measured values are then checked to sit inside them with margin.
LOCK 2's spread (19.8 mm of standoff, 1.0° of heading) is the honest one: it is
where the walk actually stopped.

**2. `disp` is identically zero while the scripted lock is on, which would make
any "settled" term trivially true.** Checked: both LOCK evaluations happen in
windows where the scripted base is FREE (SETTLE, MOVE), and neither RELEASE term
uses `disp`. So no term is being validated against a state the scripted lock
itself produced. This was worth checking — an early variant with a 5-tick
debounce appeared to fire LOCK 1 at +15 ticks, and the reason was exactly this:
it was firing *after* the phase machine had already frozen the base.

### The settled test has to be measured over a whole gait period

The obvious "is the base still?" test — XY travel over the previous 0.5 s — does
not work, and the reason is TR2: the locomotion policy IS the balance controller
and its in-place march never stops. Over **0.52 s** (13 ticks, 0.65 of a gait
period) the march has a net displacement that says nothing about whether the
robot is going anywhere:

| window | `disp ≤ 10 mm` during the settled portion of SETTLE | longest run of false |
|---|---|---|
| 0.52 s (13 ticks) | 30% of ticks | 19 ticks (0.76 s) |
| **0.80 s (20 ticks) = one `GAIT_PERIOD`** | **98.7% of ticks** | 23 ticks, rare |

Sampling an integer number of gait periods cancels the limit cycle. `GAIT_PERIOD
= 0.8` is fixed inside the network (TR4), so 20 ticks is a constant, not a tuned
value. With the 0.8 s window, the settled portion of SETTLE reads p50 0.2 mm /
p95 4.5 mm / max 25.4 mm, against 10.2–430 mm while walking in.

TR8 applies directly (a single-frame stillness threshold is not a stillness
test), so the predicate is debounced. It is **not** monotone even at 0.8 s — the
march wanders — so the lock must **latch**: LOCK and RELEASE are edge triggers on
a two-state latch, never a continuously re-evaluated condition. That is also what
the phase machine does.

### The predicate

State-only. No phase, no tick index, no elapsed time. `s` is the 47-D vector;
every term is a `g1_data.spec` accessor plus the two fixed platform constants.

```
GOAL_XY   = (1.5, -1.5)        # scene constant, fixed by Q6/TR13
REST_Z    = 0.84               # platform top 0.75 + box half 0.09
SETTLE_W  = 20 ticks           # 0.80 s = one GAIT_PERIOD (TR4)
DEBOUNCE  = 5 ticks            # 0.20 s (TR8)

welded    = grip_left(s) >= 0.5
box_lift  = box_pos(s).z - REST_Z
to_goal   = |box_pos(s).xy - GOAL_XY|
target    = GOAL_XY if welded else box_pos(s).xy
fwd, lat, head = target expressed in the PELVIS frame (from base_pos, base_quat)
disp      = |base_pos(s).xy - base_pos(s[t-SETTLE_W]).xy|
palm_far  = max(|palmL_pos(s) - box_pos(s)|, |palmR_pos(s) - box_pos(s)|)

LOCK    := disp <= 0.010
           and 0.26 <= fwd <= 0.40
           and |lat| <= 0.05
           and |head| <= 5 deg
           and not (not welded and to_goal <= 0.10)      # task already done

RELEASE := (welded and box_lift >= 0.055)                # carrying: hand to the legs
        or (not welded and to_goal <= 0.10
            and |box_lift| <= 0.020
            and palm_far >= 0.25)                        # placed and withdrawn
```

Both branches of each predicate must hold for DEBOUNCE consecutive ticks, and the
lock latches: LOCK is only tested while free, RELEASE only while locked.

Why each term is there, and why the "task already done" guard is not optional:
at LOCK 1 the robot is settled at a standoff from a box at rest with the hands
far away — which is *also* what RELEASE 2's placed-and-withdrawn branch
describes, and after RELEASE 2 the box sits at the goal standoff directly in
front of a settled robot, which is what LOCK's geometry describes. Without
`to_goal` the two would each fire in the other's situation. `to_goal <= 0.10` is
the Q4 placement tolerance, i.e. the predicate asks "is the box where the task
wants it", which is exactly the distinction needed. It costs one scene constant.

### Margins

Worst value over the 12 seeds at the transition tick, against the threshold.

| transition | term | worst at transition | threshold | margin |
|---|---|---|---|---|
| LOCK 1 | `disp` | 0.0002 m | ≤ 0.010 | **+9.8 mm** |
| LOCK 1 | `fwd` (box) | 0.3267 m | [0.26, 0.40] | **+66.7 mm** to the near edge |
| LOCK 1 | `\|lat\|` | 0.0130 m | ≤ 0.05 | +37.0 mm |
| LOCK 1 | `\|head\|` | 2.287° | ≤ 5° | +2.71° |
| LOCK 1 | `to_goal` (not done) | 1.378 m | > 0.10 | +1.278 m |
| RELEASE 1 | `box_lift` | 0.0614 m | ≥ 0.055 | **+6.4 mm** |
| LOCK 2 | `disp` | 0.0011 m | ≤ 0.010 | +8.9 mm |
| LOCK 2 | `fwd` (goal) | **0.2791 m** | [0.26, 0.40] | **+19.1 mm** |
| LOCK 2 | `\|lat\|` | 0.0098 m | ≤ 0.05 | +40.2 mm |
| LOCK 2 | `\|head\|` | 2.010° | ≤ 5° | +2.99° |
| RELEASE 2 | `to_goal` | 0.0389 m | ≤ 0.10 | +61.1 mm |
| RELEASE 2 | `\|box_lift\|` | 0.0001 m | ≤ 0.020 | +19.9 mm |
| RELEASE 2 | `palm_far` | 0.3278 m | ≥ 0.25 | +77.8 mm |

The two thin ones are `RELEASE 1 box_lift` (+6.4 mm) and `LOCK 2 fwd` (+19.1 mm).

- `box_lift` is thin because the arm only achieves **61.4 mm** of the commanded
  80 mm lift. The threshold trades directly against how early it fires:
  0.030 → −23 ticks, 0.045 → −16, **0.055 → −9**, 0.060 → −4 with only 1.4 mm of
  margin (no debounce; with DEBOUNCE = 5 the chosen 0.055 lands at −5). 0.055 is
  the compromise. **This term is tied to `DemoConfig.lift_h`**;
  change the lift and it must be re-measured.
- `LOCK 2 fwd`: **2 of 12 seeds (3 and 11) arrive at 0.2791 / 0.2798 m**, which is
  *below* the conservative band `GraspConfig` ships (`[0.28, 0.36]`, `assert_standoff`)
  though inside the A1-measured 0.28–0.40. Both still placed successfully (0.0479
  and 0.0486 m, the two worst of the 12). Flagged, not fixed: the walking arrival
  at the goal can land marginally outside the band the pickup asserts.

Threshold sensitivity, measured with the debounce off so the term is seen on its
own: `RELEASE 1 box_lift` moves −23 → −4 ticks over 0.030→0.060, `RELEASE 2
palm_far` −14 → −2 ticks over 0.20→0.32. Both graceful, neither cliff-edged.

### Would it have fired in time? N per transition

Evaluated offline on the recorded trajectories, alternating latch, DEBOUNCE = 5.
**All 12 seeds fire at all four transitions; none is missed.** Offsets are
negative = fires EARLIER than the scripted transition.

| transition | offset, ticks | offset, s | **N** | per-seed spread |
|---|---|---|---|---|
| LOCK 1 | −268 … −258 | −10.7 … −10.3 | **268** | 10 ticks |
| RELEASE 1 | −5 (all 12) | −0.20 | **5** | **0** |
| LOCK 2 | −318 … −215 | −12.7 … −8.6 | **318** | 103 ticks |
| RELEASE 2 | −5 … −3 | −0.20 … −0.12 | **5** | 2 ticks |

**The two RELEASE transitions track the phase machine to 5 ticks — 0.2 s.** That
is the answer the question wants: they are usable as drop-in replacements.

**The two LOCK transitions fire ~10 s early, and that is not predicate error —
it is dead time in the schedule.** Both leads land in windows where nothing
task-relevant happens:

| window | duration | samples | base net wander | box motion | joint action |
|---|---|---|---|---|---|
| SETTLE, after the walk converges | 10.3–10.7 s | 258–268 | 17.6–19.4 mm | 0.0 mm | **exactly constant** |
| MOVE, after arrival at the goal | 8.6–12.7 s | 215–318 | 12.5–28.9 mm | 19–59 mm | **exactly constant** |

The MOVE dead tail is new and was not previously recorded: **the robot reaches
the goal standoff at t = 30.4–33.5 s and then marches in place for 10–13 s**
because `move_s_walk = 16.0` is a fixed duration sized for the worst case. With
the SETTLE dead prefix (2026-09-10 audit: 292–316 samples) that is **~500–600 of
the 1253 samples — 40–48% of every episode — spent holding station**. A
predicate-driven lock removes both by construction.

**Validity limit, stated plainly.** This is an OFFLINE counterfactual on
trajectories the phase machine produced. It is honest only up to the first
transition the predicate would move: had LOCK 1 fired at tick 82–92 instead of 350,
everything after diverges, so RELEASE 1 / LOCK 2 / RELEASE 2 are "when the
predicate would fire on the scripted trajectory", which is necessary but not
sufficient. The closed-loop check — drive the demonstrator from the predicate and
re-run the 12-seed gate — is a demonstrator change and is Charles's call.

### Rejected while measuring

**A "the lift has finished" term** — `box_lift ≥ 0.055` **and** `|Δbox_lift| ≤ 1 mm
over 0.2 s` — to make RELEASE 1 fire nearer the scripted tick. It fires **+33 to
+495 ticks** instead: the cosine ease is asymptotic, so the box is still creeping
at the end of LIFT, and the moment MOVE starts the walk bounces the welded box far
past 1 mm per 0.2 s. It only becomes true deep in RELEASE. Dropped. The plain
height threshold at −12 ticks is better than any settling test on a carried box.

### Also measured: the carry sag, and 5.7 mm of clearance

Not part of the predicate, but it fell out and it is a risk worth recording. The
box is lifted **61.4 mm** above resting at RELEASE 1, and arrives at the goal at
**3.7–23.0 mm**: the arm sags **38–58 mm under the box during the transport walk**
(the dead tail costs only a further −2 to +6.5 mm, so it is the walking, not the
time). At LOCK 2 the box bottom clears the goal platform top by **5.7 mm on 10 of
12 seeds** (16.5 mm on seeds 3 and 11). The place succeeds every time, but the
margin between "carries the box in" and "drags it onto the platform edge" is
under 6 mm, and it is not something the current gate would notice.

### For Charles

1. The predicate is defined but **not built**. When it is, it belongs beside the
   phase labels — `g1_data/phases.py` in the planned tree — and must import its
   accessors from `g1_data/spec.py`, not re-derive them.
2. Adopting it changes the demonstrator (the lock stops being a phase transition),
   which is out of scope here and needs the 12-seed gate re-run.
3. It removes 40–48% of every episode's samples. That interacts directly with
   O10's cap: an episode driven by this predicate is **670–772 samples, mean 739,
   not a flat 1253** — and it stops being a constant, so the cap becomes a
   distribution and the phase balance changes with it.
4. `LOCK 2 fwd` at 0.279 m on 2 of 12 seeds sits outside `GraspConfig`'s shipped
   `[0.28, 0.36]`. Either the band's lower edge is conservative (A1 measured
   0.28–0.40) or the goal arrival needs the same treatment O22 gave the pickup.

Throwaway scripts in the scratchpad: `lock_record.py`, `lock_derive.py`,
`lock_report{1,2,3,4}.py`. Nothing added to the repo.

---

## 2026-09-10 — Demonstrator changes 1–5: four adopted, ONE NOT ADOPTED (the gate said no)

Five changes were implemented. **Changes 2–5 are adopted and pass the exit gate
12/12 on every measure.** **Change 1, the event-driven lock, is implemented,
closed-loop verified, and left DISABLED by default** (`DemoConfig.lock_predicate
= False`), because it drops the gate to 8/12. The reason it fails is worth more
than the change was: it exposed a 2 mm margin the 12/12 gate has been resting on
since the walking place was adopted.

### The gate, adopted configuration (12 seeds, `walk_place=True`, walk-in)

| measure | before (2026-09-09) | after | verdict |
|---|---|---|---|
| full task | 12/12 | **12/12** | held |
| weld gate fired | 12/12 | **12/12** | held |
| palm error at grasp | 35.4 mm | **34.5 mm** | held |
| within the 45 mm guard | 12/12 | **12/12** | held |
| commanded-but-refused weld | 0 | **0** | held |
| box drift during transport | 2.5–2.8 mm | **2.43–2.79 mm** | held |
| placement error | 0.0397 mean / 0.0486 max | **0.0415 mean / 0.0428 max** | max improved |
| over the 0.10 m Q4 limit | 0/12 | **0/12** | held |
| resting + upright | 12/12, tilt 0.00° | **12/12, tilt 0.00°** | held |
| falls, during and after release | 0 | **0** | held |
| max pitch | 8.5° | **10.7°** | **REGRESSED 2.2°** |
| min transport clearance | **−1.4 mm (scraped)** | **+10.2 to +23.6 mm** | fixed |
| clearance at the second lock | 5.7–16.5 mm | **20.4–35.4 mm** | fixed |
| goal standoff | 0.279–0.299 (2/12 out of band) | **0.289–0.313 (12/12 in band)** | fixed |
| samples per episode | 1253 | **1278** | +25, GRASP |

The one regression is **max pitch 8.5° → 10.7°**, against a 25° limit. It is the
price of `lift_h`: the box is held 35 mm higher and further from the body through
the carry. Disclosed, not fixed - it is less than half the limit and no seed came
near a fall.

**TR18 note.** Palm error is 34.544–34.548 mm across all 12 and placement clusters
into two values (0.0373–0.0382 / 0.0427–0.0428). That is the station-keeper
artifact already recorded on 2026-09-09 and 2026-09-10: the base tracks a
*box-relative* standoff, so the pelvis-frame geometry is identical every episode
and only the world position varies. It is not new and it is not evidence of
anything working.

### Change 2 — `lift_h` 0.08 → 0.12, measured first

Swept on the unchanged demonstrator, 12 seeds per value, all from stepped state.
"Achieved" is the box centre above resting height at the moment of RELEASE 1;
"clearance" is the box bottom above the platform top at the second lock.

| commanded `lift_h` | achieved lift | clearance at LOCK 2 | min clearance in transport | gate | peak `torso_link` |
|---|---|---|---|---|---|
| 0.08 | 61.2 mm | 8.8–17.8 mm | **−1.4 mm (it scrapes)** | 12/12 | 303.7 N |
| 0.10 | 78.4 mm | 12.8–27.5 mm | +6.6 mm | 12/12 | 302.8 N |
| **0.12** | **95.9 mm** | **21.4 mm** | +10.6 mm | 12/12 | **215.6 N** |
| 0.14 | 113.7 mm | 35.9–60.2 mm | +14.3 mm | 12/12 | 299.2 N |
| 0.16 | 131.8 mm | 50.4–76.6 mm | +25.4 mm | 12/12 | 301.3 N |

Achieved tracks commanded linearly with a **~19 mm constant deficit** - the arm
sags under the box by a fixed amount, it does not saturate. **0.12 is the
smallest value meeting both targets** (≥80 mm achieved, ≥20 mm clearance).

Raising it does **not** reopen a reach or self-collision problem, checked across
all 12 seeds at every value: peak `torso_link` force is *lowest* at 0.12
(215.6 N), `platform_pickup` is flat at 489–550 N, and nothing new appears. In
the adopted configuration the peak non-foot contacts are `pelvis`/`platform_goal`
1288 N (pre-existing - the pelvis meets the goal slab at the standoff, the
`max_base_x` mechanism from O13), `platform_pickup` 489 N, `torso_link` 282 N.

At 0.12 the clearance at the second lock reads **21.4 mm on all 12 seeds** in the
sweep. Suspicious under TR18, and checked: it is the same station-keeper artifact
as the palm error - the carry pose is identical in the pelvis frame every
episode, so the sag equilibrium is too. In the adopted run (with the shorter
approach to the goal) it spreads to 20.4–35.4 mm.

**The −1.4 mm at `lift_h = 0.08` is the important number.** The box was already
brushing the pickup platform on the way out, in every episode ever recorded, and
nothing measured it.

### Change 3 — the goal standoff: target moved, not asserted

Chosen: **move the navigation target**, `goal_standoff_bias = 0.03`, so
`hold_target = goal_x − standoff − bias`. Not an assertion, and the reason is the
same one O22 settled: the standoff at the goal is an **outcome** of where the
walk stops, not a precondition anything could check beforehand. An assertion
would reject episodes that place perfectly well (both 0.279 m seeds placed at
0.048 m, inside a 0.10 m tolerance) and would fire *after* the work was done.
Measured deficit was 21–41 mm; the bias is the middle of it.

Result: arrivals move from **0.2791–0.2989 (2 of 12 outside `[0.28, 0.36]`)** to
**0.2892–0.3132, 12/12 inside**, worst margin 9.2 mm instead of −0.9 mm.

The check is still recorded - `goal_standoff` and `goal_standoff_ok` are in the
result dict - so a future drift is visible in the metrics rather than silent.
That is the O22 lesson applied: a guard where the standoff is actually known.

### Change 4 — `grasp_s` 0.6 → 1.6 s

GRASP goes from 15 to **40 samples**, 1.2% → 3.1% of the episode. The weld still
engages at `frac ≥ 0.5`, so the extra time is dwell at the grasp pose, not a
slower approach. No effect on any gate measure.

### Change 5 — the scrape check

`DemoConfig.min_clearance = 0.005`. `min_clearance_m` is now recorded per
episode and a violation sets `fail_phase = "TRANSPORT(clearance)"` and clears
`ok`. Measured **only during MOVE**, and only while the box is actually over a
platform footprint: LIFT begins and LOWER ends with the box resting, so a minimum
across those would read zero every time and mean nothing; between the platforms
the box is over the floor and `PlatformGeometry.clearance` returns NaN, which is
skipped. `inf` (never over a platform) is treated as "the metric did not run",
not as a pass.

Adopted configuration: **0/12 rejected**, min clearance 10.2–23.6 mm. At the old
`lift_h` the same check rejects the run that scraped.

### Change 1 — event-driven lock: it works, and the gate still says no

Implemented in full: `g1_data/phases.py` holds `PlatformGeometry`, `LockConfig`
and `LockPredicate` (a two-state latch over the 47-D spec state, thresholds and
5-tick debounce exactly as measured on 2026-09-10, no re-tuning). The predicate
replaces `LOCKED_PHASES_WALKING`; SETTLE and MOVE end on the lock event with
their old durations as max-duration fallbacks; every other phase keeps its fixed
duration; interpolation stays duration-based. The step-index `bounds` list became
a duration list walked with a cursor, because with two event-ended phases no
later boundary has a fixed step index any more.

Verified before wiring: replaying the 12 recorded episodes through
`LockPredicate` reproduces the offline counterfactual **tick for tick** (LOCK 1
at 88/92/84/83/82/91/87/91/92/89/84/85, LOCK 2 at 869/850/875/…, RELEASE 1 at
685 on all 12).

**Closed loop, it does exactly what it was built to do:**

| | result |
|---|---|
| all four transitions fired | **12/12 seeds** |
| max-duration fallback used | **only on the 4 seeds that had already failed the grasp** |
| SETTLE | 350 → **82–92 samples** |
| MOVE | 400 → **142–222 samples** |
| episode length | 1278 constant → **694–813, mean ~750** |

**And the gate drops to 8/12.** Seeds 1, 5, 7, 8 - the four largest +y spawns -
fail at GRASP with palm error 258–302 mm, the box never welded, left on the
pickup platform (place error 1.6 m).

**The mechanism, measured.** Pelvis height at the lock instant separates pass
from fail with no overlap:

| | `base_z` at the first lock | achieved palm error |
|---|---|---|
| passing seeds (8) | **0.7780–0.7811** | 28–36 mm |
| failing seeds (4) | **0.7715–0.7726** | 258–302 mm |
| phase-driven lock (all 12) | **0.7748** | 34.5 mm |

Below roughly 0.774 m the REACH sweep drives the wrists **under** the platform
slab and they jam there **permanently** - traced on seed 1:
`right_wrist_yaw_link` vs `platform_pickup` at 94–120 N and
`right_wrist_roll_link` vs `right_wrist_yaw_link` at 59–68 N from t = 8.4 s to
the end of the episode, with `right_wrist_pitch_joint` stuck **1.42 rad** off its
command throughout. The arm never reaches the box.

**This is O26, and it was always there.** The 2026-09-10 audit measured all 12
episodes wedging at least one wrist during REACH, 8 of 12 past 1.0 rad, and
recorded it as a transient that recovers. It recovers only when the pelvis is
high enough. The old fixed 14 s SETTLE always locked at the same point in the
gait cycle - `base_z = 0.7748`, about 2 mm above the cliff - which is why it
recovered every time. **The 12/12 gate has been resting on a 2 mm margin that no
measurement was watching**, and the event-driven lock, which samples the gait at
whatever phase the predicate fires in, found it.

**TR16 trap (a), again, exactly as written.** The twin IK residual at the lock
instant is **26.9 mm on the failing runs and 27.3 mm on the passing ones**. The
kinematic twin cannot see this failure at all; the achieved palm distance is a
factor of ten apart. Nothing that gates on `PoseBook.solve`'s residual would have
caught it.

**What was deliberately NOT done.** A `base_z >= 0.774` term in `lock_ok` restores
12/12 and is legal - dim 9 is in the state vector. It is not added. It would tune
the LOCK around a broken REACH path rather than fix it, which is the TR16 pattern
this project keeps paying for, and a 5 mm gap measured on 12 samples is one spawn
away from not being a gap. The fix belongs in the reach path: O19's IK
formulation, not the waypoints, and not the lock.

The implementation stays behind `lock_predicate=False`. Once the reach path
clears the slab, it is one flag.

### Constant-dimension audit, re-run — the mask did NOT move

| | result |
|---|---|
| HARD-CONSTANT action dims | **6, 13, 14, 15, 16** - unchanged |
| `a_gR` bit-identical to `a_gL` | **yes** - dim 18 still degenerate |
| `spec.CONSTANT_ACTION_DIMS` | **(6, 13, 14, 15, 16, 18)** - still correct |
| newly hard-constant dims outside the mask | **none** |
| state dims that became constant | **NONE**; all 47 still LIVE |
| tightest state dims | `q_right_wrist_yaw` 2.3e-3, `q_waist_yaw` 2.6e-3, `base_pos_z` 6.3e-3 |

**`g1_data/spec.py` needs no version bump and was not touched.** Episode-invariant
action dims are unchanged too (4, 5, 6, 11, 12, 13, 14, 15, 16, 17, 18).

### Episode length

Adopted configuration: **1278 samples on all 12 seeds, 51.10 s** - still a
constant, because with the event-driven lock disabled every phase runs its fixed
duration again. Per-phase: SETTLE 350 · REACH 75 · REPOSITION 150 · APPROACH 50 ·
**GRASP 40** · LIFT 50 · MOVE 400 · LOWER 50 · RELEASE 50 · VERIFY 63.

**So O10's cap is 1278, not 1253 and not the ~750 the event-driven lock would
have delivered.** The 40–48% saving is real and was measured working (694–813
samples, all four events firing); it is blocked behind O26, not behind the
predicate. Two dead windows remain in every recorded episode: ~262 samples of
SETTLE after the walk converges, and ~215–318 samples of MOVE after arrival at
the goal.

### Files

- **new** `g1_data/phases.py` - `PlatformGeometry`, `LockConfig`, `LockPredicate`.
  Imports its accessors from `g1_data/spec.py`, as the 2026-09-10 section
  required. The `Phase` enum stays in `scripted_demo.py` for now; moving it is a
  separate refactor.
- **changed** `g1_data/scripted_demo.py` - `lay_out` returns durations not step
  bounds and the loop walks it with a cursor; lock/release edges come from the
  predicate when enabled; the goal re-solve is keyed on "this is the second lock"
  rather than `phase is LOWER` (with the predicate driving, the re-lock happens
  on the last tick of MOVE, so the phase test would never have matched and the
  place chain would have silently kept the pickup solve - TR14(d)); new config
  fields and result fields.
- **untouched** `g1_data/spec.py`, `CLAUDE.md`.

### The retired stationary path still passes: 10/10

Re-run on the final code with `walk_place=False`: **10/10**, palm 24.2 mm,
placement 0.0477-0.0957 m against the 0.10 m limit (the historical figure was
0.047-0.097), carry drift 0.17-0.25 mm, max pitch 3.0 deg, no scrapes,
640 samples. It keeps the phase-set trigger: the predicate's release condition
(box lifted and carried) fires exactly at the start of its lateral MOVE sweep,
which is the one place that variant needs the base held.

`lift_h = 0.12` and `grasp_s = 1.6` apply to it as well and cost it nothing -
placement is unchanged to the millimetre and its transport clearance is
86-95 mm, an order of magnitude clear of the 5 mm rejection threshold.

---

## 2026-09-10 — O26 diagnosed: the reach sweeps the pads THROUGH the platform, in every episode

Diagnosis only; nothing implemented, nothing in the demonstrator, `spec.py` or
CLAUDE.md changed. Four questions, then three proposals.

**The headline, and it is worse than "four seeds fail":** the adopted 12/12
configuration drives a palm pad **into** the pickup platform slab in **12 of 12
episodes**, 6.9–9.1 mm deep, for 0.36–1.04 s of every REACH. The gate passes
because the pad usually slides off. Sometimes it hooks, and then the episode is
lost. Every demonstration already in scope contains this collision.

**And a correction to the previous section.** The 2026-09-10 four-change
validation recorded the failure as gated on pelvis height at the lock instant,
"a sharp cliff at ~0.774 m with no overlap". **That is wrong.** It was twelve
samples of two confounded variables. Both parts are refuted below.

### Q1 — the actuator IS clamped, at 5 N·m, not 25 and not unbounded

Case **(a)**. The audit's −692 N·m was `data.actuator_force`, the *unclamped*
scalar output of the position servo. The torque actually delivered to the DOF is
`data.qfrc_actuator`, and it is clamped by the JOINT's `actuatorfrcrange`, which
is where the XML attribute lands (`model.jnt_actfrcrange`), not by
`model.actuator_forcerange`.

Read from the model at the peak of the wedge (seed 1, t = 4.88 s):

| field | value |
|---|---|
| `model.actuator_forcelimited[right_wrist_pitch]` | **0** — `actuator_forcerange` is `[0, 0]`, unlimited |
| `model.jnt_actfrclimited[right_wrist_pitch_joint]` | **1** |
| `model.jnt_actfrcrange[right_wrist_pitch_joint]` | **[−5, +5] N·m** |
| `data.actuator_force` | **−731.3 N·m** (unclamped servo demand) |
| `data.qfrc_actuator` | **−5.00 N·m**, pinned, every step |
| `data.qfrc_constraint` on the same DOF | **+4.98 N·m**, opposing |
| `data.qpos` | **+1.629 rad**, against a joint range of ±1.61443 |

Two corrections fall out. **The wrist pitch and yaw joints are ±5 N·m, not the
±25 N·m quoted for the arm** — ±25 is shoulder/elbow/wrist-roll; the two wrist
joints that jam are the weakest in the chain. And the audit's "the servo answers
a 1.3 rad error with −692 N·m, unbounded" is wrong: **the jam is bounded, at
5 N·m.**

This decides the class of fix. The arm is not overpowering anything - it is
**stalled at its rated torque against a contact of the same magnitude**, with the
joint simultaneously pressed past its range limit. No fix that relies on the
servo pulling harder can work without changing the robot's declared actuator
limits, which would make every result non-physical.

### Q2 — the geometry, and the death of the pelvis-height story

**Which segment.** Confirmed: `home -> P["up"]`, the **first half of REACH**, at
**t = 0.94–1.12 s into it** (94–112 ticks after the lock). Every measurement
below puts the minimum there. The first geometry to enter the slab is a **palm
pad**, not a wrist link.

**Clearance vs `base_z`: no effect.** A controlled sweep. The full stepped state
(`qpos`, `qvel`, `ctrl`) was captured from a real episode one step before the
lock; for each height the state was restored verbatim, **only the pelvis z
changed**, the base welded there exactly as `BaseLock` does it, the pose chain
re-solved from the live pelvis→box offset exactly as the demonstrator does, and
the two REACH segments replayed under stepped physics. Clearance is
`mj_geomDistance` between the platform's collision geom and every pad/wrist
collision geom - true mesh separation, nothing from the twin. Leg pose is
irrelevant to this measurement: with the pelvis welded the arms and legs are
separate chains hanging off it.

| captured seed | `base_z` swept | min clearance across the sweep | outcome |
|---|---|---|---|
| 1 (real run FAILS) | 0.7680 → 0.7860 (18 mm) | **−12.9 to −13.6 mm** | **wedged at every height** |
| 0 (real run PASSES) | 0.7680 → 0.7860 (18 mm) | **−7.2 to −8.2 mm** | **clear at every height** |

Over an 18 mm sweep - three and a half times the claimed 5 mm cliff - the
clearance moves by **0.7 mm** and the outcome never changes. **Pelvis height is
not the mechanism.**

**The cliff was twelve samples.** Re-run at 40 seeds with the predicate driving:

| | passing | failing | overlap? |
|---|---|---|---|
| `base_z` at lock | 0.7780–0.7812 | 0.7714–**0.7796** | **YES** |
| lateral offset at lock | −0.0133 to +0.0081 | **+0.0048** to +0.0212 | **YES** |

24/40 pass. At `base_z = 0.7796` there are four seeds: three pass, one fails.
`corr(base_z, pass) = +0.90`, `corr(lateral, pass) = −0.87`, and
**`corr(base_z, lateral) = −0.93`** - the two candidate predictors are
confounded with each other, because the predicate fires at one of a handful of
gait phases and each phase carries its own (height, lateral) pair. Neither
separates the outcomes once the sample is big enough to see it. This is exactly
the trap the brief named, and it caught my own previous section.

**What DOES vary with the outcome** is the depth of penetration, and it is
bistable at the contact rather than continuous. In the rig, shifting the pelvis
laterally on seed 0's captured state flips the outcome between
`lat = −0.0077` (clear, −8.0 mm) and `lat = −0.0127` (**wedged**, −10.0 mm), and
the pad that hooks is always the one on the side **away** from the box - the
right pad for `lat > 0`, the left for `lat < 0`. But the same threshold does not
transfer between seeds: seed 3 runs at `lat = −0.0133` in reality and passes. So
**no scalar we have measured predicts hook-vs-slide.** It is the outcome of a
7–13 mm interpenetration resolving one way or the other.

**Which is why the important number is the one that does not vary.** In the
ADOPTED, phase-driven, 12/12 configuration:

| seed | 0 | 1 | 2 | 3 | 4 | 5 | 6 | 7 | 8 | 9 | 10 | 11 |
|---|---|---|---|---|---|---|---|---|---|---|---|---|
| min pad-to-slab, mm | −8.4 | −7.7 | −8.9 | −7.8 | −8.7 | −6.9 | −7.8 | −8.8 | −9.1 | −7.3 | −8.3 | −8.7 |
| ticks penetrating | 33 | 31 | 23 | 18 | 52 | 42 | 29 | 36 | 28 | 42 | 43 | 21 |
| pad | L | R | L | L | R | R | L | R | R | L | L | R |

**12/12 penetrate, 6.9–9.1 mm, always during REACH at t ≈ 14.7–15.1 s.** The
shipping demonstrator collides with the platform in every demonstration it
records. The 12/12 gate is not measuring the absence of this; it is measuring
that the pad happened to slide off.

### Q3 — why it never recovers

Three things hold it, and the schedule removes none of them.

1. **The servo is saturated.** `qfrc_actuator` sits at exactly −5.00 N·m, the
   joint's rated limit, pulling the right way; `qfrc_constraint` opposes it at
   +4.98 N·m. Escape needs more torque than the joint has.
2. **The joint is past its range limit** (+1.629 rad against ±1.61443), so part
   of the constraint force is the limit itself.
3. **The command never changes again.** `ctrl` on the wrist pitch ramps to
   `WRIST_NATURAL` = 0.200 during REACH and **stays at 0.200 for the rest of the
   episode** - every later waypoint (`high`, `side`, `grasp`, `lift`, `move`,
   `lower`, `open`, `clear`, `out`) carries the same pinned wrist value (D2).
   Nothing ever commands the wrist back out.

The shoulder and elbow keep tracking normally after the jam (elbow
`qfrc_actuator` −13 N·m against a ±25 limit, tracking error 0.05 rad), so the
arm does travel to its later waypoints - **with the hand folded 1.4 rad back**,
which is what leaves the palms 258–302 mm from the box.

**What would have to change:** either the contact reaction is removed (the arm
lifts the wrist out from under the slab, which requires a commanded pose that
moves the hand *backwards and up*, and the schedule only ever moves it forward
and down), or the wrist gets more than ~5 N·m, which means changing declared
actuator limits. **Nothing in the current schedule can supply either.** The one
phase that moves the hand away from the box - the RELEASE retract, `open →
clear → out` - happens 30 s later at the *goal* platform, and by then the
episode has already failed.

### Q4 — the teleop path IS exposed, and it is the same hazard

Measured as a **clearance map**, not a trajectory, so it applies to any path:
for a grid of palm targets in the pelvis frame the arm IK produces joint angles,
those angles are written into the **stepped** model at a real captured lock pose,
and `mj_geomDistance` measures pad/wrist geometry against the slab. No twin
residual anywhere.

Clearance of the nearest pad/wrist geom to the slab, mm, negative = inside it:

| palm height (world) | forward 0.10 | 0.14 | 0.18 | 0.22 | 0.26 | 0.30 | 0.34 |
|---|---|---|---|---|---|---|---|
| 0.90 | (clear) | 22.5 | (clear) | 49.3 | (clear) | 70.0 | (clear) |
| 0.86 | 3.8 | −9.6 | 6.6 | 19.6 | 32.7 | (clear) | (clear) |
| **0.84 (box centre)** | **−22.8** | **−25.4** | **−10.2** | **2.3** | (clear) | 28.6 | 42.4 |
| 0.80 | −59.6 | −55.9 | −41.9 | −30.0 | −17.1 | −3.4 | 11.5 |
| **0.75 (slab top)** | −43.0 | −49.9 | −63.1 | −65.3 | −59.2 | −44.4 | −26.1 |

**At box height the hand is inside the slab for every palm position from 0.08 to
0.22 m forward of the pelvis**, and only clears from 0.24 m outward. The box sits
at ~0.33 m forward. So **any** hand path that travels outward at box height -
which is what a human reaching for a box on a table does - crosses a 140 mm band
where the hand geometry is inside the platform. The only clear way to box height
is to be *already past* 0.24 m forward before descending, which is precisely the
staged descent TR17 added, and precisely what the `home -> P["up"]` raise does
not do.

The hazard is therefore **shared, not demonstrator-specific**: it is a property
of this arm's geometry against this scene, with the wrists pinned (D2). The
teleop path has the same 4-DOF pinned-wrist IK, the same hand geometry and the
same collision-blind solve, and it has **no staged waypoints at all** - the
human's hand goes where it goes. Under O25 it has never run under stepped
physics, so this has never been observable there.

**What the map does not cover:** ZED noise, One-Euro smoothing, retargeting
scale, what a human hand actually does, the dynamics of getting there (a fast
path can overshoot into a cell it never commanded), and the possibility that a
human would naturally arc high - which the map says is the safe thing to do.
`mj_geomDistance` also returned exactly 0.0 for scattered cells in the
high-clearance region where the neighbours read 20–90 mm; those cells are
unreliable and are excluded above. The negative region is corroborated
independently by the contacts actually observed in the runs.

### Proposals — three, none implemented

**P1. Raise first, then reach out: an intermediate waypoint above the band.**
The map says the safe corridor is z ≥ 0.86–0.90 near the body and z ≥ 0.84 from
0.24 m forward. A path that rises to ~0.90 m close in, translates forward at
that height, and only then descends to box height never enters the band. Note
that **both endpoints are already clear** - `P["up"]` is at 0.10 m forward and
~0.98 m high, which the map scores clear - so this is not a waypoint-position
problem: **joint-space interpolation between two clear poses passes through poses
that are not clear.** Any added waypoint must therefore be validated on the
*segments*, not the endpoints.
*Changes:* the REACH waypoint list only. *Risks:* O19 - waypoints near the body
are exactly what the 4-DOF IK cannot serve (117–218 mm residual), so a high
close-in waypoint may not be reachable; and subdividing does not guarantee
clearance, it only shortens the segments. Every sub-segment needs the
`mj_geomDistance` check above. *Protects teleop:* **no**. *Cost:* small, plus a
full 12-seed re-validation.

**P2. Collision-aware IK.** The root cause shared with O19 and O24: the twin IK
never checks collision, so it returns poses and paths that intersect the scene
and nothing downstream can tell. Add a contact check to the solve (the twin can
run `mj_forward` and read `ncon` cheaply) and either reject-and-repair the pose
or add a clearance term to the nullspace objective; extend the same check to the
interpolation between consecutive waypoints.
*Changes:* `g1_teleop/ik.py` and `PoseBook.solve`. *Risks:* the largest of the
three - it changes every pose the current gate depends on, so the grasp, the
place chain and the standoff band all need re-measuring; it may reintroduce the
IK branch-flipping that anchored seeding fixed; and it makes the solve slower in
a loop that runs per episode. *Protects teleop:* **yes**, if the same check goes
into the live `solve_arm_ik` path - this is the only proposal that does.
*Cost:* large. It is also the only one that addresses O19 and O24 at the same
time, which is three open issues for one fix.

**P3. Stand the pads down during the reach, as the weld already does.** The
geometry that penetrates first is the **pad**, in 12 of 12 episodes, and the
pads are detection-only (D11): they are never pressed, and `GraspWeld.engage`
*already* zeroes their `geom_contype`/`conaffinity` while the weld carries the
box, restoring them on release. Doing the same from the start of REACH until the
approach removes the hooking geometry entirely.
*Changes:* a few lines, reusing a mechanism that exists and is already trusted.
*Risks:* it may only relocate the problem - the rig shows `right_wrist_yaw_link`
contacting the slab at 44–120 N *after* the pad does, so the wrist link may hook
instead; and it makes the demonstrator's hand pass *through* the platform, which
is physically false and would have to be disclosed as a modelling choice rather
than a fix. It also removes the pads' only remaining function during REACH.
*Protects teleop:* **partially** - the same pad geoms are the first thing in the
way on any path, but the wrist link is not covered. *Cost:* smallest to try,
and it is the fastest way to test whether the pad is the whole story.

**Recommendation, for Charles to decide:** P3 first as a *measurement* - it costs
almost nothing and it answers whether the pad is the only offender, which
determines how much of P1 or P2 is actually needed. P2 is the real fix and the
only one that protects Objective 1's teleop path, and it retires O19 and O24 with
it. P1 is the cheapest thing that could restore `lock_predicate=True` and its
40–48% episode saving, but it protects nothing else and it does not remove the
collision from the 12 episodes that currently pass.

**Not proposed, per the brief and now with evidence:** a `base_z` term in the
lock predicate. The controlled sweep shows pelvis height does not change the
clearance at all, the 40-seed run shows it does not separate the outcomes, and
the 5 mm gap it was based on does not exist.

Throwaway scripts in the scratchpad: `q1_force.py`, `q2_cliff.py`, `q2_rig.py`,
`q2_adopted.py`, `q4_teleop.py`.

---

## 2026-09-10 — O26 fix: STOPPED AT STEP 1. There is no reachable corridor.

Step 1 was run and **failed**, so per the stop rule Steps 2 and 3 were not
attempted and nothing was implemented. The demonstrator, `spec.py` and
CLAUDE.md are untouched.

**The answer: NO.** The safe corridor is geometrically real and
**kinematically unreachable**. Above the slab the arm cannot place the palms
anywhere closer than 0.28 m forward of the pelvis without exceeding the 45 mm
palm guard; at the heights where it *can* reach close in, the hand is inside the
slab. The two constraints have an **empty intersection everywhere forward of the
body and short of 0.28 m**, which is exactly the span any path from the home pose
to the grasp has to cross.

### Method

Palm targets on a (forward × height) grid in the pelvis frame, at the grasp
separation, solved with the current IK. **The residual is never used** (TR16(a):
26.9 mm on failing runs vs 27.3 mm on passing ones, separating nothing). For each
cell the solved joint angles are applied to the **stepped** model at a real
captured lock state, held by the real position servos for 0.5 s of physics, and
then measured:

- **achieved** palm error - `site_xpos` of both palm sites against their goals,
  expressed in the pelvis frame so base yaw cannot contaminate it;
- clearance to `platform_pickup_geom` from every pad/wrist collision geom.

Captured state: pelvis z 0.7796, box at forward 0.330, lateral +0.002,
dz +0.060; home palms at forward 0.002 / 0.001, i.e. **essentially at the body**.

### Achieved palm error, mm, on stepped state (guard = 45)

| z \ fwd | 0.10 | 0.14 | 0.18 | 0.22 | 0.26 | 0.28 | 0.30 | 0.32 | 0.34 |
|---|---|---|---|---|---|---|---|---|---|
| 0.94 | 140 | 107 | 97 | 84 | 71 | 64 | 57 | 50 | **43** |
| 0.92 | 131 | 102 | 93 | 81 | 68 | 61 | 54 | 47 | **40** |
| 0.90 | 118 | 98 | 89 | 77 | 64 | 57 | 50 | **44** | **37** |
| 0.88 | 99 | 94 | 85 | 73 | 60 | 54 | 46 | **40** | **33** |
| 0.86 | 89 | 87 | 80 | 69 | 56 | 49 | **42** | **35** | **29** |
| **0.84** | 87 | 77 | 69 | 61 | 51 | **44** | **37** | **30** | **25** |
| 0.82 | 82 | 69 | 60 | 51 | 41 | 36 | 31 | **25** | **22** |
| 0.70 | 62 | 53 | **41** | **31** | 49 | 58 | 96 | 96 | 94 |
| 0.68 | 56 | **45** | 54 | **33** | 47 | 56 | 65 | 114 | 113 |

Bold = within the guard. The error falls **monotonically with forward
distance** at every height above the slab: at z = 0.88 it runs 99 / 94 / 85 / 73
/ 60 / 46 mm across forward 0.10 → 0.30. Nothing above the slab is inside the
guard until 0.30 m forward. The only close-in cells inside the guard are at
z = 0.68–0.72, which is **at slab height**.

**This is O19, measured on stepped state for the first time.** O19's "117–218 mm
residual" was a twin number and is not citable (TR16(a)). The honest, achieved
figure for the same region is **56–131 mm**. The conclusion is unchanged and now
rests on evidence that survives the trap.

### Usable cells, and why they are unreachable

Usable = achieved error ≤ 45 mm **and** no penetration.

| z | usable forward positions |
|---|---|
| 0.94, 0.92 | 0.34 |
| 0.90, 0.88 | 0.32, 0.34 |
| 0.86 | 0.30, 0.32, 0.34 |
| **0.84** | **0.28, 0.30, 0.32, 0.34** |
| 0.82 | 0.32, 0.34 |

**15 usable cells out of 255, every one of them at forward ≥ 0.28 m.** They form
a single connected component and it does contain the grasp cell (forward 0.33,
z 0.84, achieved error 25 mm). But **there is not one usable cell anywhere
between the body and 0.28 m forward, at any height from 0.62 to 0.94 m.** The
home pose puts the palms at forward ≈ 0.00. So the component is an island: the
arm can hold the grasp, and it cannot get there.

Where the two criteria fail, they fail for opposite reasons:

- **above the slab** (z ≥ 0.86, forward 0.06–0.26): the hand is **clear** -
  measured pad clearance +27 to +80 mm, zero contacts - but the achieved palm
  error is **56–131 mm**, far outside the guard. The pose is safe and wrong.
- **at slab height** (z 0.68–0.72, forward 0.18–0.24): the arm **can** reach -
  achieved error 28–37 mm - but the hand is **18–20 mm inside the slab**, with
  8–10 real contacts carrying **978–1006 N**.

### A second measurement artifact, recorded so it is not rediscovered

`mj_geomDistance` returns **exactly +0.0 for box-vs-MESH pairs at real positive
separation** in this build. Probed directly: cells reporting +0 have **zero
contacts and zero contact force**, and the nearest geom in every such cell is a
wrist *mesh* (`left_wrist_yaw_link`, `left_wrist_pitch_link`,
`left_wrist_roll_link`); wherever the nearest geom is a *pad* (a box primitive)
the same call returns a plausible positive number (+27, +32, +80 mm).

So: **negative values are trustworthy** - they are corroborated by real contacts
and forces - and **+0.0 means "not measured", not "touching"**. The 2026-09-10
O26 diagnosis excluded scattered zeros in its Q4 map as unreliable; that was the
right call, and this is the reason. Any future clearance work on the wrist meshes
should gate on `d.ncon` / `mj_contactForce` rather than on this distance.

### What P2 would have to change - and it is bigger than "add collision checking"

The framing in the previous section was that P2 = collision-aware IK. **That is
necessary and not sufficient.** A collision-aware solver, given a target in the
close-in band, would correctly report that no collision-free pose exists within
the guard - because none does. The blocker there is **reach**, not
collision-blindness.

P2 therefore has two parts and both are required:

1. **Restore close-in reach.** The IK must put the palms within 45 mm at forward
   0.10–0.26 m at z ≥ 0.86, where it currently achieves 56–131 mm. That region is
   already collision-free, so this alone opens the corridor. It is a formulation
   change, and the specific thing to change is **D2**: 4 joints per arm with the
   wrists pinned at `WRIST_NATURAL` and a 6-D elbow+wrist task (D3). The pinned
   wrist is what forces the hand's orientation, and the hand's orientation is
   what puts the pad low and the palm site short. Unpinning one or both wrist
   DOF adds freedom exactly where the geometry is failing. **D2 exists because
   the wrist-twist artifact made the grasp pose unusable**, so reversing it
   reopens that, and it changes the action vector's constant dims - dims 6 and 13
   are `spec.py`'s mask and are asserted there. This is a version-bump-sized
   change, not a tweak.
2. **Add collision awareness to the solve and to the path.** Once feasible poses
   exist, the solver must prefer them and the *interpolation between* consecutive
   waypoints must be checked pose-by-pose, because both current endpoints are
   already clear and the segment between them is not - that is the whole of O26.

Only part 1 is on the critical path. Part 2 without part 1 changes nothing.

### What this leaves blocked

- **`lock_predicate = True` stays off.** Its 40–48 % episode-length saving
  (694–813 samples against 1278) remains hostage to this, and the pre-fix
  baseline of 24/40 stands unimproved.
- **The adopted 12/12 configuration still drives a pad 6.9–9.1 mm into the
  platform in all 12 episodes.** Nothing in this session changed that, and the
  minimum-clearance gate criterion the brief asked for cannot be adopted yet: it
  would fail 12/12 of the demonstrations the project currently relies on.
- **Objective 1's teleop path remains exposed** by the Q4 map in the previous
  section, and part 1 above is the only proposal that would protect it.

### Limitations of this measurement

One captured lock pose, one lateral offset (+0.002), the **grasp** palm
separation (0.18 m) throughout - the real `up`/`high`/`side` waypoints use the
wider 0.24 m approach separation, so the map does not literally score the current
waypoints. It scores whether the corridor is *servable at all*, which is the
question that picks the fix. O19 measured the same close-in region across
separations 0.24–0.48 and found the same wall, so the conclusion is not an
artifact of the separation chosen here. The grid is 0.02 m; a corridor narrower
than that would not be seen.

Throwaway scripts: `s1_reach.py`, `s1_which.py` (with `q2_rig.py` for the state
capture).

---

## 2026-09-11 — O26 three-segment reach: NOT contact-free. Stopped, as instructed.

The correction to the previous session was right and is accepted: the 45 mm palm
guard belongs to the grasp, not to poses the hand passes through, and Step 1 was
wrong to apply it to via points. Re-run on contact only, the answer is still no -
but for a different and better-supported reason, and with a result that changes
what should happen next.

**No three-segment path was found that is contact-free across lock states.**
Nothing was implemented; the demonstrator, `spec.py` and `CLAUDE.md` are
untouched.

**But the staged path removes the failure.** The best candidate cuts
contact-steps by 96-98% and **eliminates the permanent wedge on every state that
currently wedges**. It does not meet the zero-contact bar this brief set, so it
is reported for decision rather than adopted.

### The geometry claim, verified from the model

| | |
|---|---|
| `platform_pickup_geom` | centre x 1.500, half-extent x 0.190 → spans **1.310 – 1.690**, top z **0.750** |
| pelvis at the lock | x 1.186 |
| near edge in front of the base | **0.124 m** (the brief assumed ~0.14) |
| other collision geoms within 0.20 m in front of the base | **none** |

So the premise holds: at forward ≤ 0.12 nothing is underneath the hand at any
height. The margin is 4 mm, not 20.

### The mechanism, traced pose by pose

Contacts gated on `d.ncon` + `mj_contactForce`, never `mj_geomDistance`.

Home palms sit at forward **+0.002**, lateral ±0.238, z **0.606**, separation
**0.476 m**. The current `home -> P["up"]` lerp then does this:

| frac | L fwd | L z | R fwd | R z | contacts |
|---|---|---|---|---|---|
| 0.40 | +0.128 | 0.643 | +0.130 | 0.657 | 0 |
| **0.47** | **+0.150** | **0.663** | **+0.146** | 0.675 | **4, 54 N** |
| 0.53 | +0.142 | 0.667 | +0.144 | 0.687 | 4, 72 N |
| 0.67 | +0.121 | 0.692 | +0.222 | 0.806 | 1, 23 N |

**The hand bulges forward to 0.150 m while still at z 0.663** - past the 0.124 m
near edge and below the 0.750 m slab top, i.e. underneath it. Both endpoints are
clear; the arc between them is not. That is the entire bug, confirmed.

The bulge is **kinematic, not a tracking error**: it is where the joint-space
lerp puts the hand, because the shoulder pitches forward before the elbow lifts.

### What was searched

~290 candidate paths, each replayed under stepped physics with the base welded
at a real captured lock state, every interpolated pose sampled.

| parameterisation | candidates | best result |
|---|---|---|
| one via, position only, at `wide` separation | 48 | all collide; **segment 1 always** |
| one via, position **and separation** swept | 72 | 37 contact-steps (one state) |
| two vias (low + high), box-relative lateral | 72 | **0 on the tuned state**, 23-281 across four |
| two vias, multi-state objective, box lateral | 48 | best worst-case 196 |
| two vias, multi-state, lateral **0** (body-relative raise) | 48 | best worst-case 121 |
| **Cartesian subdivision**, 4-10 sub-waypoints | 4 | **best worst-case 66** |

Scoring against a single lock state finds contact-free chains easily - three of
them. **None survives being scored against four states.** The four span
lat −0.010 to +0.020 and pelvis z 0.7715 to 0.7809, which is the spread the lock
predicate actually samples.

Keeping the palms **wide** through the raise is what helps most: home is at
0.476 m separation and every first search forced it to 0.24 m *while* rising, and
the lerp answers that with the forward bulge. Sweeping separation cut contacts
from 108-582 steps to 37.

### Why contact-free is not reachable this way

Cartesian subdivision should have removed an arc, and it did not - and it is
**not monotone in subdivision count** (4→3: 101, 6→4: 98, 8→5: 217, 10→6: 66).
That non-monotonicity is the tell, and it points back at O19.

In the close-in region the **achieved** palm position differs from the commanded
one by **56-131 mm** (measured on stepped state, 2026-09-10). A via point there
is "safe and wrong" - which is fine for a *destination*, exactly as the brief
says. But it is not fine for **steering**: routing a hand through a 4 mm margin
at the slab edge requires placing it to better than 4 mm, and the mechanism
available places it to 56-131 mm, with an error that changes direction from cell
to cell. Adding waypoints re-rolls that error rather than reducing it.

**So the blocker is the same one, stated more precisely than before:** it is not
that the corridor is unreachable (it is reachable - the region is clear and the
arm gets there). It is that the *path through it is not controllable* at the
resolution the geometry demands.

### The result that matters anyway

Best candidate - Cartesian, 10 sub-waypoints up the back at lateral 0 from the
home palm height to box+0.02, then 6 out to the existing `P["high"]`:

| state | real outcome | OLD contact-steps | OLD wrist error | NEW contact-steps | NEW wrist error | wedged? |
|---|---|---|---|---|---|---|
| 0 | pass | 311 | 0.001 | **11** | 0.001 | no |
| 1 | **FAIL** | 1636 | **1.418** | **40** | **0.001** | **no** |
| 5 | **FAIL** | 1737 | **1.418** | **96** | **0.001** | **no** |
| 8 | **FAIL** | 1525 | **1.419** | **37** | **0.001** | **no** |
| 10 | pass | 486 | 0.001 | **66** | 0.001 | no |
| 3 | pass | 250 | 0.001 | **0** | 0.001 | no |

**3 of 3 wedging states stop wedging.** The wrist tracking error goes 1.418 rad →
0.001 rad, which is the difference between an arm folded 80° back for the rest of
the episode and an arm at its commanded pose. Contact-steps fall 96-98%, and the
residual is a graze of 0-96 steps at 33-119 N rather than a hook.

This was **not** adopted: the brief's bar for via points is zero contacts, and
this is not zero. It is reported because it changes the decision.

### What a disclosure-only path would have to state

If Charles chooses to ship the current reach unchanged and disclose, the
limitations section has to say all of this, not a softened version:

1. **Every demonstration in the dataset contains a collision between the robot's
   hand and the pickup platform.** Measured across the adopted 12/12
   configuration: a palm pad penetrates the slab by **6.9-9.1 mm** for **0.36-1.04 s**
   of every REACH, in **12 of 12** episodes. This is not an occasional artifact.
2. **The demonstrations are therefore not kinematically feasible motions** in the
   sense a real robot could execute - they rely on the simulator resolving an
   interpenetration that hardware would resolve as an impact.
3. **The success rate is a coin-flip on that collision.** Whether the pad slides
   off or hooks is bistable and is not predicted by any measured scalar. With the
   fixed 14 s SETTLE the gate reads 12/12 because the lock always lands at the
   same point in the gait; with the lock fired from an observable predicate -
   which is what deployment and teleoperation both require - it reads **24/40**.
4. **A policy trained on this learns the collision.** The hand path through the
   slab is in the action sequence, and BC/ACT will reproduce it.
5. **The root cause is D2 + collision-blind IK**, shared with O19 and O24: the
   4-DOF pinned-wrist formulation places the palms to 56-131 mm in the region the
   path must cross, and the twin never checks contact. Objective 1's teleop path
   has the same IK and no staged waypoints at all, so it is exposed too (Q4 map,
   2026-09-10) - and per O25 it has never run under physics, so this has never
   been observable there.
6. **`lock_predicate = True` cannot be enabled**, so the 40-48% episode-length
   saving (694-813 samples against 1278) stays unavailable and O10's cap stays at
   **1278**.

### Recommendation

The staged Cartesian raise is worth adopting **on the evidence that it removes
the wedge**, not on the evidence that it removes the collision - it does not. If
Charles wants it, the next step is the validation this brief specified but
conditioned on contact-freedom: the 12-seed gate, minimum hand-to-platform
clearance as a first-class metric, the 40-seed predicate run against the 24/40
baseline, and the episode-length distribution. That is a decision about whether a
96% reduction with the failure mode removed is worth taking while the collision
itself remains.

The alternative remains the one Step 1 identified: fix the IK so the close-in
region is placeable, which is out of scope here and is a `spec.py` version bump.

Throwaway scripts: `s2_path.py`, `s2_trace.py`, `s2_trace2.py`, `s2_search2.py`,
`s2_search3.py`, `s2_search4.py`, `s2_search5.py`, `s2_cart.py`, `s2_wedge.py`.

---

## 2026-09-11 — O26 MITIGATION adopted: staged raise. Predicate gate 24/40 → 40/40.

The zero-contact bar is withdrawn, as decided. The new bar is **no wedge**, and
the staged raise meets it. Adopted, validated, and recorded as a **mitigation**:
it does not remove the collision, it removes the failure the collision causes.

`CLAUDE.md` and `g1_data/spec.py` untouched.

### Step 1 — the standoff lever, closed

Re-ran the best staged chain at standoff **0.36** against the same four lock
states, capturing each from a real episode at that standoff.

| standoff | seed 0 | seed 1 | seed 8 | seed 10 | worst | total | any wedge |
|---|---|---|---|---|---|---|---|
| 0.32 (current) | 11 | 0 | 0 | 67 | 67 | 78 | no |
| **0.36** | 0 | 18 | 0 | 11 | **18** | **29** | no |

Standing back does help - contact-steps fall 63% - but it **does not reach zero
on all four states**, so the clean path does not exist there either.

**And it costs the grasp.** Palm error at the grasp, achieved on stepped state:

| standoff | seed 0 | seed 1 | seed 8 | seed 10 |
|---|---|---|---|---|
| 0.32 | 36.1 | 274.1 | 257.6 | 33.9 |
| 0.36 | **50.4** | 273.7 | **79.9** | 27.5 |

Two of four go **over the 45 mm guard** (50.4 and 79.9 mm) where they were
inside it at 0.32. The corridor map's 25 mm at forward 0.34 was a settled
single-pose measurement; the walk-in does not arrive where the map assumed, and
`edge ahead` at a nominal 0.36 standoff actually spans 0.125–0.200 m across
seeds, not a fixed 0.170.

**Question closed: keep standoff 0.32.** The 4 mm margin is not the whole story
and buying more of it costs more than it returns.

### Step 2 — adopted, and validated

`DemoConfig.staged_reach = True` (default). REACH becomes a Cartesian chain:
**10 sub-waypoints straight up the body** at lateral 0, from the palms' measured
home height to 0.02 m above the box, palms held at the home separation and
closing to 0.30 m; then **6 sub-waypoints out** to `P["high"]`. Total REACH
duration is unchanged at 3.0 s, so the episode length under the phase lock is
unchanged at 1278 samples.

Three details that matter:
- the raise starts from where the palms **actually are**, measured on the stepped
  model at the lock instant, not from a constant;
- the last sub-waypoint **is** `P["high"]`, solved the existing way (anchored back
  at the grasp), so REPOSITION, APPROACH and everything downstream start from
  exactly the pose they always did;
- interpolation is **Cartesian** because a joint-space lerp between two clear
  poses is what arcs through the slab. The whole chain is still solved once at
  the lock instant and played open loop, so TR15 does not apply.

**1. Phase 1 exit gate, 12 seeds, phase-driven lock: 12/12.** Nothing regressed.

| measure | before this change | after | verdict |
|---|---|---|---|
| full task | 12/12 | **12/12** | held |
| palm error at grasp | 34.5 mm | **34.5443–34.5481 mm** | held |
| within the 45 mm guard | 12/12 | **12/12** | held |
| placement error | 0.0373–0.0428 | **0.0376–0.0429** | held |
| over the 0.10 m limit | 0/12 | **0/12** | held |
| box drift in transport | 2.43–2.79 mm | **2.45–2.79 mm** | held |
| max pitch | 8.4–10.7° | **8.4–10.7°** | held |
| min transport clearance | 10.2–23.6 mm | **10.5–20.8 mm** | held |
| resting, upright, falls | 12/12, 0 | **12/12, 0** | held |
| samples | 1278 | **1278** | held |

**2. Minimum hand-to-platform clearance, now always reported.** Measured as
contact **penetration depth** (`contact.dist`), not `mj_geomDistance` - that call
returns +0.0 for box-vs-mesh at real separation (TR19), so a positive clearance
is deliberately not claimed. 0.0 means "never touched".

| | 12-seed gate |
|---|---|
| hand-vs-pickup contact steps | **35–225** (mean 108) |
| deepest penetration | **−7.5 to −15.7 mm** (mean −12.0) |
| peak contact force | **73–270 N** |

**This is not a pass/fail criterion and cannot be while any collision remains.**

**The honest comparison, like for like** (same metric, staged vs not, same seeds):

| seed | staged: steps / depth / force | unstaged: steps / depth / force |
|---|---|---|
| 0 | **196** / −10.85 mm / 187 N | 714 / −8.53 mm / 75 N |
| 1 | **80** / −13.73 mm / 129 N | 634 / −7.68 mm / 49 N |

Contact **duration** falls 72–87%. **Penetration depth and peak force go UP.**
The mitigation shortens the collision and stops it hooking; it does not make it
gentler. That must be disclosed as-is.

**3. Wrist deviation from command — the new gate criterion.**

Two quantities, and conflating them scores every passing episode as a failure:
the 2026-09-10 audit measured **all 12 seeds** wedging a wrist *transiently*
during REACH, up to 1.42 rad, and recovering. What loses an episode is the wedge
that does not recover, and D2 makes that permanent - the wrist command never
changes after REACH, so a jam surviving into REPOSITION survives to the end. So
the gate watches **post-REACH** deviation only.

It also watches the **wrist pitch pair only**. Measured: after REACH the left
wrist **yaw** sits **0.55–0.57 rad** off command in the configuration that passes
12/12, because the welded box hangs off that link and the joint is rated 5 N·m.
Gating all six at 0.5 rad would fail every healthy episode.

And the threshold is **0.8 rad, not the 0.5 proposed**, set from the two
populations rather than from a round number:

| | post-REACH wrist-pitch deviation |
|---|---|
| healthy episodes (12-seed gate) | **0.297–0.490 rad** |
| the diagnosed wedge | **1.418 rad** |
| threshold adopted | **0.800 rad** (0.31 below, 0.62 above) |

0.5 would have left 14 mrad of margin against healthy runs. Transient in-REACH
deviation is reported separately (`wrist_dev_reach_rad`, 0.030–0.899 rad) and
gates nothing.

`wedged` now sets `fail_phase = "WEDGE(<joint>)"` and clears `ok`.

**4. `lock_predicate = True`, 40 seeds: 40/40.** The number that decides it.

| | pre-fix | **after** |
|---|---|---|
| predicate gate | **24/40** | **40/40** |
| wedges | 16 | **0** |
| falls | 0 | **0** |
| placement over the 0.10 m limit | — | **0/40** |
| palm over the 45 mm guard | — | **0/40** |
| all four transitions fired | — | **40/40** |
| max-duration fallback used | — | **0/40** |
| palm error | — | 30.1–36.1 mm |
| placement error | — | 0.0316–0.0523 m |
| max pitch | — | 6.7–14.1° |
| post-REACH wrist pitch | — | 0.158–0.647 rad, all under 0.8 |

**`DemoConfig.lock_predicate` is now `True` by default.** It was off because it
exposed O26; the wedge is gone, so it goes on.

**5. Episode length under the predicate — the new O10 input.**

| | |
|---|---|
| samples | **694 – 846**, mean **757**, median 766, sd 41 |
| seconds | 27.74 – 33.82, mean 30.26 |
| against the 1278 constant | **34% – 46% shorter, mean 41%** |

**O10's cap is now a distribution, not a constant: 846 is the max over 40 seeds.**
A cap must be set from a distribution with margin, not from a single number, and
it stops being schedule-derived - two phases end on an event.

**The retired stationary path still passes 10/10**, palm 24.2 mm and placement
0.0477–0.0957 m unchanged to the millimetre, with hand-platform contact steps
0–37. It uses the same staged raise.

### Step 3 — this is a MITIGATION, and the root cause stays open

**What was fixed:** the wedge. A pad hooking under the slab and jamming a wrist
1.42 rad off command for the rest of the episode - unrecoverable under D2, and a
data-destroying failure - becomes a graze the arm rides through.

**What was not fixed:** the collision. The hand still enters the pickup platform,
now 7.5–15.7 mm deep for 35–225 steps of every episode. The demonstrations are
still not motions a real robot could execute without impact, and a policy trained
on them still learns a hand path that goes through the table.

**Root cause, unchanged and still open:** collision-blind IK plus D2 (pinned
wrists), shared with **O19** and **O24**. The twin never checks contact, and the
4-DOF pinned-wrist formulation places the palms to 56–131 mm in the region the
path must cross - which is why the path cannot be steered through a 4 mm margin
however many waypoints it is given. That belongs in limitations and in future
work, and Objective 1's teleop path has the same IK with no staged waypoints at
all (Q4 map, 2026-09-10), so it remains exposed.

**For the Phase 5 demonstrator protocol.** This is measured evidence, not
ergonomic advice: **raising the hands up the body before reaching out removes the
wedge.** Contact duration falls 72–87% and the failure rate goes 24/40 → 40/40 on
that change alone. A human teleoperator who reaches straight out at table height
crosses the same band the scripted lerp crossed. It should be a **training
instruction** in the collection protocol, and the recorder should keep watching
`wrist_dev_rad` so a session where the operator does not follow it is visible in
the metrics rather than silent.

### Config, as adopted

`staged_reach=True`, `raise_sub=10`, `out_sub=6`, `raise_top=0.02`,
`raise_sep=0.30`, `wedge_rad=0.8`, `lock_predicate=True`, `standoff=0.32`
(unchanged), `lift_h=0.12`, `grasp_s=1.6`.

New result fields: `hand_plat_contacts`, `hand_plat_depth_mm`,
`hand_plat_force_N`, `wrist_dev_rad`, `wrist_dev_reach_rad`, `wrist_dev_any_rad`,
`wrist_dev_joint`, `wrist_dev_phase`, `wedged`.

Throwaway scripts: `s3_standoff.py`, `s3_pred40.py` (with `s2_*` from the
routing search).

---

## 2026-09-11 — spec 1.1.0: two schema gaps closed. Phase 2 work ends here.

Both gaps were things the episode file would have contained without `spec.py`
owning them, and both freeze the moment collection starts. `SPEC_VERSION` is now
**`g1-spec-1.1.0`**. `CLAUDE.md` untouched — the closeout prompt handles it.

### Gap 1 — the velocity dims during locked phases are a PHANTOM

**Measured first, across the 12 gate seeds, 15336 ticks.**

| question | answer |
|---|---|
| does the station-keeping / policy block run while the base is locked? | **no** |
| `locked` vs "legs PD-held at DEFAULT_ANGLES" | agree on **15336 of 15336** ticks |
| is `act` defined during locked ticks? | yes — a **stale** value |
| does it change while locked? | **24 of 5580 ticks**, and those 24 are the two lock transitions × 12 seeds |
| is it consumed? | no — `carry.obs[6:9] = act * cmd_scale` sits **inside** the skipped block |
| is it applied? | no — the legs are PD-held at `DEFAULT_ANGLES` regardless |
| fraction of each episode locked | **36.4%**, identical across seeds (schedule-driven under the phase lock) |

**Verdict, plainly: it is a phantom.** The demonstrator computes it before the
lock, then holds it frozen for 36% of the episode while nothing reads it and
nothing acts on it. The base *is* genuinely locked — the more serious finding the
brief asked me to watch for did not occur, and the 0-of-15336 disagreement
between the weld bit and the leg-hold is the evidence.

What it would have put in the dataset: **nonzero on 100% of locked ticks**, with
`vy = −0.732` held constant right through REACH→LIFT. A policy trained on that
learns to emit a large lateral walking command while grasping, and to expect
nothing to happen.

**Adopted:** dims 19–21 are **zero whenever the base lock is engaged**, in
collection and deployment alike. The lock state is read from the model's own
equality (`SpecLayout.base_lock_id`), not taken on the caller's word, so the
logged semantics cannot drift from the physics. `act` is still **required** —
the caller must say what the command was, so there is one code path — it is
simply ignored when locked.

The channel now has legible phase structure:

| window | dims 19–21 |
|---|---|
| SETTLE (walk-in) | live |
| REACH → LIFT | **zero** |
| MOVE (transport) | live |
| LOWER → RELEASE | **zero** |
| VERIFY | live |

**The open-loop replay test is unaffected, and the claim holds.** Replay
reproduces the state trajectory, the lock predicate re-fires from that state at
the same tick, and during locked ticks the locomotion policy is not queried — so
substituting zeros for the phantom changes nothing that is read. It is in fact
*more* robust: a replay that naively fed the recorded velocities to the
locomotion policy would previously have injected a −0.73 lateral command during
the grasp. The one case where it would matter is a replay that ignores the lock
entirely, and that replay is already wrong for a larger reason — it would have
unlocked base dynamics too.

### Gap 2 — the phase vocabulary now lives in the schema

`Phase` and `ScoredPhase` are `IntEnum`s in `spec.py`, with **explicit integers
that are the file format**:

| phase | int | scored |
|---|---|---|
| UNKNOWN | −1 | (none — not a phase the demonstrator performs) |
| SETTLE | 0 | GRASP |
| REACH | 1 | GRASP |
| GRASP | 2 | GRASP |
| LIFT | 3 | LIFT |
| MOVE | 4 | TRANSPORT |
| LOWER | 5 | PLACE |
| RELEASE | 6 | PLACE |
| VERIFY | 7 | PLACE |
| REPOSITION | **8** | GRASP |
| APPROACH | **9** | GRASP |

REPOSITION and APPROACH sit out of execution order because they were added after
VERIFY already existed. **They are deliberately not renumbered** — tidying them
into sequence would silently relabel every episode already recorded, which is
exactly the failure the explicit integers exist to prevent. A comment in the
source says so.

The 10 → 4 mapping (proposal §3.8.3) is **data**, `SCORED_OF: Dict[Phase,
ScoredPhase]`, not a body someone can quietly edit — so it can be asserted over,
printed, and stored beside a dataset. Everything up to and including securing the
box scores as GRASP, because the approach phases are *how* the grasp is achieved
and a failure in any of them is a failed grasp. LOWER/RELEASE/VERIFY are all
PLACE: the box is not placed until it has been let go and stayed put, which is
what VERIFY measures.

Accessors: `spec.scored_phase(label)` (scalar or vectorised over an array,
returning −1 for UNKNOWN rather than raising, because a dataset may legitimately
contain it) and `spec.phase_name(label)`. `PHASE_DTYPE = np.int8`.

Load-time assertions, in the `ModelIndex` spirit: integers unique; `PHASES` lists
the 10 real phases exactly once and excludes UNKNOWN; the mapping is **total**
over the 10 and maps nothing that is not a phase; **its image is exactly the four
scored phases** — a scored phase with no source phase would report 0/0 for a
whole dataset and nobody would notice; and the integers fit the dtype.

**One vocabulary, one place.** `g1_data/scripted_demo.py` now does
`from g1_data.spec import Phase` and its own definition is gone; the
demonstrator-specific rationale for REPOSITION and APPROACH stays there as
comments, because it is about the demonstrator, not the schema. A test asserts
`scripted_demo.Phase is spec.Phase`.

**Recorded in the docstring: phase labels are NOT a policy input** (2026-09-08).
They exist for the per-phase failure taxonomy and the data-scaling analysis. The
consequence, stated so nobody builds the wrong thing: **teleoperated episodes do
not need a live phase classifier.** Every boundary the taxonomy needs is already
a function of the 47-D state — the weld bit gives grasp and release, box height
above resting gives lift and lower, base-to-box distance gives approach and
transport — so labels can be derived **offline** from the recorded trajectory.
Nothing in collection has to know the phase while it is happening.

### Validation

**Tests: 41/41** (was 31/31; 10 new, covering the frozen integers, the mapping's
totality and image, the accessors, the demonstrator sharing the enum, the
zeroing rule, and that `act` is still required when locked). One new test
deliberately breaks `SCORED_OF` two ways — removing a phase, and remapping MOVE
so the image loses TRANSPORT — and checks `_validate_phases` catches both.

**Only dims 19–21 changed, and only on locked ticks.** Rebuilt the 22-D action
on all 12 gate episodes, comparing each tick against a non-zeroing build:

```
dims that ever differ:  [19, 20, 21]
ticks differing:        5580   (locked ticks: 5580 — exact overlap)
```

Every phase integer and its scored mapping were also confirmed against real
recorded ticks, not just the table above.

**Gates, both unchanged.**

| | 12-seed, phase lock | 40-seed, predicate |
|---|---|---|
| result | **12/12** | **40/40** |
| palm error | 34.5443–34.5481 mm | 30.09–36.15 mm |
| placement | 0.0376–0.0429 m | 0.0316–0.0523 m |
| carry drift | 2.45–2.79 mm | 2.41–2.78 mm |
| max pitch | 8.40–10.65° | 6.73–14.14° |
| falls / wedges | 0 / 0 | 0 / 0 |
| over the 0.10 m limit | 0 | 0 |
| over the 45 mm guard | 0 | 0 |
| samples | 1278 | 694–846, mean 757, sd 41 |

Identical to the pre-change numbers to four decimals. Nothing regressed.

### What a 1.0.0 loader needs to know

Recorded in the module docstring: a 1.0.0 file may contain a **stale
station-keeper output** in dims 19–21 during locked ticks, and its phase column —
if it has one — has undocumented integers. `assert_spec_version` refuses to mix
them, which is what it was built for.

### Phase 2 is done

`spec.py` now owns the state vector, the action vector, the permutation, the
constant-dim mask, the normalization contract, the clip limits, the timing
convention, the velocity semantics during locked phases, and the phase
vocabulary. Nothing about the episode file is left for the recorder to decide.

Next is the closeout, then Phase 3.

Throwaway scripts: `g1_vel.py`, `g2_check.py`, `g2_gates.py`.

---

## 2026-09-11 — spec: fifth failure-attribution bucket, `ScoredPhase.WALK_IN`

Small, focused. `SETTLE` no longer charges its failures to the grasp.

**Why it matters, and it is not cosmetic.** The spatial variation Objective 4 is
scored on lives almost entirely in the walk-in: the base absorbs the spawn
position and the arms then execute a near-identical motion — measured
2026-09-10, arm-command variance *across* episodes is **3%** of the variance
*within* one. So a policy that fails on a held-out box position will most likely
fail by walking to the wrong place, and charging that to "grasp failure" would
hide the exact effect the thesis exists to measure.

### What did NOT change — stated here because it is easy to misread

**The metric set is untouched.** The four success rates in proposal §3.8.2 /
§3.8.3 are **episode-level OUTCOME criteria** evaluated on the final state. A
robot that falls during the walk-in fails the grasp criterion regardless of any
per-tick label. `SCORED_OF` is used **only for failure attribution** — which
bucket a failed episode lands in. The reported success rates stay exactly as the
proposal specifies; the taxonomy gains a category, nothing else. This is now
said in `SCORED_OF`'s own comment and in the module docstring, so a future
reader cannot conclude the metrics moved.

### The change

`ScoredPhase` gains a **fifth member, appended at 4**:

| bucket | int |
|---|---|
| GRASP | 0 |
| LIFT | 1 |
| TRANSPORT | 2 |
| PLACE | 3 |
| **WALK_IN** | **4** |

Appended, not slotted in front of GRASP where it belongs chronologically, for
the same reason `REPOSITION = 8` and `APPROACH = 9` were left out of order:
these integers go into files, and renumbering silently relabels everything
already recorded.

**Named WALK_IN, not APPROACH.** `Phase.APPROACH` already exists in the same
module and means the *arm* descending beside the box — it maps to GRASP, not to
this. Two different things called APPROACH in one module is a trap, and there is
now a test (`test_walk_in_is_not_phase_approach`) whose only job is to keep them
apart.

Mapping, 10 → 5:

| phase | scored |
|---|---|
| **SETTLE** | **WALK_IN** |
| REACH, REPOSITION, APPROACH, GRASP | GRASP |
| LIFT | LIFT |
| MOVE | TRANSPORT |
| LOWER, RELEASE, VERIFY | PLACE |

**REPOSITION is a judgement call and is recorded as one.** It is the base
closing the standoff gap, so it is arguably locomotion and arguably WALK_IN. It
stays under GRASP because it happens **after arrival** — the robot is already at
the box, and what it is fixing is the recession the *reach itself* caused, not
where it walked to. A WALK_IN failure should mean "went to the wrong place", and
REPOSITION failures do not mean that. The reasoning is in a comment beside the
mapping, so it is a decision rather than an accident.

### Version: amended 1.1.0 in place

Checked before deciding: **no `.npz` exists anywhere in the project**, the 36
files in the scratchpad are diagnostic dumps that carry no version key, and no
recorder exists yet to have written one. So no episode file has ever been
written at `g1-spec-1.1.0` and there is nothing to be incompatible with.
`SPEC_VERSION` stays `g1-spec-1.1.0`; the docstring's 1.1.0 note now lists this
as its third item, including the check that justified amending rather than
bumping. Had any 1.1.0 file existed the rule was to bump to 1.2.0 instead.

### Assertions

`_validate_phases` already required the image to be **exactly** `set(ScoredPhase)`,
so it generalised to five for free — but a bare set comparison would also have
passed if someone deleted a member, so an explicit `len(ScoredPhase) == 5` check
was added with a message saying why (every bucket needs a source phase, or it
reports 0/0 for a whole dataset and nobody notices).

The breaking test now covers **four** ways to get it wrong, up from two:
mapping not total; image loses TRANSPORT; **image loses WALK_IN** — the exact
regression if someone "simplifies" SETTLE back to GRASP; and mapping something
that is not a phase.

### Validation

**Tests: 43/43** (was 41; two new, one extended).

**Vector invariance — nothing moved.** The same episode was run twice in one
process, once with the adopted mapping and once with `SETTLE → GRASP` patched
back in, and the arrays diffed:

```
state arrays bit-identical : True   (max |diff| 0.000e+00)
action arrays bit-identical: True   (max |diff| 0.000e+00)
phase labels identical     : True
dims that moved            : NONE
```

This change touches labels only, as intended.

**Gates unchanged.**

| | 12-seed, phase lock | 40-seed, predicate |
|---|---|---|
| result | **12/12** | **40/40** |
| palm error | 34.5443–34.5481 mm | 30.09–36.15 mm |
| placement | 0.0376–0.0429 m | 0.0316–0.0523 m |
| carry drift | 2.45–2.79 mm | 2.41–2.78 mm |
| max pitch | 8.40–10.65° | 6.73–14.14° |
| falls / wedges | 0 / 0 | 0 / 0 |
| over 0.10 m / over 45 mm | 0 / 0 | 0 / 0 |
| samples | 1278 | 694–846, mean 757 |

Identical to four decimals in every column.

### What the buckets now weigh

Scored-phase histogram, seed 0 under the **phase-driven** lock (1278 samples):

| bucket | ticks | share |
|---|---|---|
| TRANSPORT | 400 | 31.3% |
| **WALK_IN** | **350** | **27.4%** |
| GRASP | 315 | 24.6% |
| PLACE | 163 | 12.8% |
| LIFT | 50 | 3.9% |

Under the **adopted default** (`lock_predicate = True`) SETTLE is 82–92 samples
of 694–846, so WALK_IN is roughly **10–13%** of an episode rather than 27% — the
predicate ends SETTLE on arrival instead of running a fixed 14 s. Worth knowing
before anyone reads a per-bucket rate: the buckets are not equally sized, and
WALK_IN's size depends on which lock mode produced the data.

Throwaway script: `walkin_val.py`.

---

## 2026-09-11 — Phase 2 exit item: the platform diagram exists

PLAN.md's third Phase 2 exit criterion — "a platform diagram showing training vs
held-out regions is saved for Chapter 3" — is now met.

**Files** (regenerate with `python tools/plot_platform_regions.py`):

| file | what |
|---|---|
| `docs/figures/platform_regions.pdf` | vector, for the thesis (fonts embedded, `pdf.fonttype=42`) |
| `docs/figures/platform_regions.png` | 300 dpi, for quick viewing |
| `docs/figures/platform_regions_caption.txt` | the Chapter 3 caption, generated beside the figure so the two cannot drift |
| `tools/plot_platform_regions.py` | the generator |

**No hand-placed coordinates anywhere.** The platform footprint comes from
`box_reset.platform_extent`, which resolves `platform_pickup_geom` by name, and
the box footprint from `box_reset.box_half_extent` — so a Q6 resize moves the
figure instead of silently invalidating it, which is why those helpers exist
(O3). Every number in the caption is interpolated from the same values. The
generator runs `assert_spawn_fits` and `assert_heldout_inside_region` first: if
the region does not fit the platform, or the patch is not inside the region, the
figure would be drawing a lie and it refuses instead.

**The scatter is a check, not decoration.** 2000 draws through the real
`sample_box_pose`, coloured by the real `in_heldout` — the same two functions the
recorder and the end-of-collection leak check will use.

| | |
|---|---|
| measured held-out fraction | **0.1425** (285 / 2000) |
| predicted by area | **0.1429** (0.06 × 0.12) / (0.12 × 0.42) |
| difference | 0.0004 = **0.05 sd** of a 2000-draw binomial (sd 0.0078) |

They agree. The generator prints the comparison every run and shouts if the gap
exceeds 4 sd, with the point stated explicitly: the figure is drawn from the
geometry and the scatter from the sampler, so a disagreement means the **sampler
or the config** is wrong, not the figure.

**One thing the figure corrected.** The reach limit the brief asked to draw,
`max_base_x + grasp_max` = 1.615 m, is *not* what sets the sample region's far
edge. The region stops at 1.56 m because the walk-in drives the base to
`box_x − standoff` and the far edge must leave it clear of `max_base_x` (O22) —
the standoff constraint binds ~55 mm before the arm-reach bound does. Both are
drawn, and the caption says which is which. Getting that backwards in Chapter 3
would have misattributed a locomotion limit to the arm.

**What the caption argues**, and it is the reason the patch is shaped this way:
every held-out x also occurs in training at some other y, and every held-out y
at some other x — **both marginals stay in-distribution, so only the
combination is unseen.** Objective 4 therefore measures *compositional*
generalization strictly inside the convex hull of the training data, not
extrapolation. A far-half or edge-band split would have measured the opposite
thing, which is the 2026-09-08 Q6 decision made visible.

Also visible in the figure: `edge_margin` is a *minimum* and only y sits on it
(20 mm at a corner spawn); x has 40 mm to spare because O22 trimmed it for the
standoff, not for the platform edge.

---

## 2026-09-15 — O25 PARTIAL: the teleop path under stepped physics, no camera. It wedges on the platform.

**O25 is NOT closed by this.** It closes the half that needs no camera: whether the
poses this pipeline produces are executable by a standing robot under gravity. Real
ZED noise, true human motion statistics, and operator timing and reaction are all
absent — see the last subsection.

**The headline, plainly:** with the base locked, as collection will run it, **6 of 10
teleoperated motions near the pickup platform wedge a wrist permanently**, and all 10
drive the hand into the slab. A control with the platform's collision switched off
removes **every** wedge. The staged raise that fixed the scripted demonstrator **does
not transfer through the teleop pipeline** — it is equal or worse. This is
structural, not something an operator warning or a training protocol can fix.

### What was built

- **`g1_teleop/synthetic_source.py`** — a drop-in for `ZEDSource`. `.grab()` returns a
  real `BodyFrame` with BODY_38 keypoints in the **camera** frame; non-arm keypoints are
  NaN, so a future change that starts reading one fails loudly. The inverse of
  `apply_camera_rotation` is `(v.y, -v.z, -v.x / DEPTH_SCALE)` — note the 1/0.6 on
  depth: D1 is a gain, not a rotation, so a synthetic "human" reaches 1.67x further in
  depth than the robot does. Verified to round-trip exactly. Generators:
  `replay_frames` (achieved directions -> keypoints), `hand_path_frames` and
  `with_dropout` (authored motions, NaN gaps).
- **`tools/teleop_physics_check.py`** — the harness. The stack below the camera is the
  real one, unmodified: `TeleopController` (One-Euro, depth low-pass, stillness lock,
  coast, `arm_alpha`) -> `G1Robot` twin -> `solve_arm_ik` -> twin qpos copied into
  `ctrl[ix.upper_ctrl]`; physics at 500 Hz, gravity on, locomotion policy at 50 Hz in
  the free-base runs. One frame per 17 physics steps (29.4 Hz) to match the One-Euro
  filter's `euro_freq = 30`.
- **`run_integrated_combined.py`** — one change, behind a flag: `--synthetic` swaps
  `ZEDSource` for `SyntheticSource` at its construction site. Nothing below the source
  changes. **That entry point was not run** — its loop still needs cv2 and a display.
  The measurements come from the harness, which differs from it in exactly these ways
  (TR14): the base is parked at the working standoff (the entry point leaves it ~1.2 m
  away, where the hands never reach the platform); each motion runs base-locked (D12)
  and base-free; pads are held at zero instead of driven (the TR17 bug at line 296);
  no UI. Neither is at parity with collection; that is separate work.

Every number is from the stepped model. No twin IK residual is used anywhere (TR16a):
"reachable" is the IK's **target** against the **stepped** wrist, each in its own
pelvis frame. Contacts gate on `d.ncon` + `mj_contactForce`, never `mj_geomDistance`
(TR19). Wedge = wrist-pitch deviation > 0.8 rad (TR23); "END" is after the last pose is
held 1.5 s, which separates the permanent kind from the transient.

### A rig artifact caught and removed first

The first run began every stream with the arms already out in front. Frame 0 was then
a step change in every joint target, the arm slammed through the platform on
**frame 1**, and the contact table was measuring the start-up jolt, not the motion.
Every motion now **starts at home** (15 frames, arms hanging) and ramps in over 45
frames. Home-segment contacts are **0 in all 20 runs**.

### Geometry, measured (seed 0, base at the standoff, pelvis frame)

Shoulders at z **+0.292**; limbs **0.200 / 0.184 m**; box centre **(0.32, 0, +0.05)**;
platform near edge **0.114 m** ahead of the pelvis. The home hands sit at world
z ~0.62 — **below the 0.75 m slab top**, behind its edge. Motions are authored with the
robot's own shoulders and limb lengths: retargeting keeps only segment directions and
rescales by robot lengths, so a path authored in human proportions would not put the
robot's hand "at box height" at all.

### 1. Round trip (a) — the mapping is lossy, the execution is not

The first continuous replay is **not citable**: its "settled" window had settled-mean
equal to settled-max on every joint — one pose measured 122 times (TR18) — and it
replayed LOWER/RELEASE poses, which the demonstrator executed at the **goal**, against
the pickup platform.

Replaced by a **static per-pose round trip**: 40 distinct pre-MOVE poses (40 distinct
error rows, TR18 check passes), each held 60 frames from a rig whose arm already starts
at that pose — no lag, no scene confound.

| joint | mapping mean | mapping p95 | mapping max | execution mean | execution max |
|---|---|---|---|---|---|
| L shoulder pitch | 0.094 | 0.211 | 0.303 | 0.008 | 0.051 |
| L shoulder roll | 0.044 | 0.224 | 0.271 | 0.003 | 0.018 |
| L shoulder yaw | 0.077 | 0.425 | 0.506 | 0.001 | 0.017 |
| **L elbow** | **0.283** | **0.511** | **0.540** | 0.006 | 0.026 |
| R shoulder pitch | 0.094 | 0.211 | 0.308 | 0.006 | 0.038 |
| R shoulder roll | 0.063 | 0.273 | 0.320 | 0.002 | 0.018 |
| R shoulder yaw | 0.081 | 0.405 | 0.486 | 0.001 | 0.012 |
| **R elbow** | **0.279** | **0.505** | **0.547** | 0.004 | 0.018 |
| **all 8 IK joints** | **0.127** | **0.468** | **0.547** | **0.004** | **0.051** |

Radians. *Mapping* = teleop joint output vs the source; *execution* = stepped joints
vs that output.

- **The loss is in retargeting + IK, not the servos** — execution error is 30x smaller.
- **The elbow is off 0.28 rad on average, 0.55 worst.** Body *positions* are closer —
  elbow/wrist **p50 34 mm, p95 68 mm, max 69 mm** — because the IK lands a different
  joint configuration near the same point. Likely cause, *hypothesis only*:
  `compute_arm_targets` rescales directions by limb lengths measured once at home, but
  the G1 shoulder is three offset links rather than a spherical joint, so the
  shoulder-to-elbow distance changes with shoulder roll and yaw.
- **SETTLE round-trips exactly (0.000); REACH is worst (0.547).**
- **p95 position error 68 mm is over the 45 mm palm guard**: even with perfect input,
  ~5% of the demonstrator's poses cannot be reproduced within the grasp tolerance.

**Continuous replay truncated before MOVE (454 ticks): permanent WEDGE** — wrist pitch
END **1.420 rad**, 13,333 platform contact-steps, -12.8 mm. The demonstrator's own
staged raise, wedge-free when executed directly, wedges when reproduced through
teleop, because the reproduced path is not the same path.

### 2 & 3. Scripted human (b) — what the arm does, and the question this exists for

Base **locked** (collection mode), 254 frames per run. Contact-steps split
home / ramp / motion / hold.

| motion | approach | platform contact-steps | depth mm | torso steps | pitch END | verdict |
|---|---|---|---|---|---|---|
| reach out, box height | direct | 0 / 1851 / 9339 / 2992 | -7.6 | 517 | 0.513 | transient |
| hands in, box height | direct | 0 / 1028 / 9780 / 4488 | -9.6 | 25 | 0.394 | ok |
| **hands in, chest height** | direct | 0 / 1766 / 6432 / 2052 | -12.8 | 2159 | **1.424** | **WEDGE** |
| **lateral sweep** | direct | 0 / 1811 / 5737 / 2217 | -15.9 | 1728 | **1.415** | **WEDGE** |
| **dropout 3/5/8** | direct | 0 / 2371 / 6455 / 2244 | -12.0 | 0 | **1.419** | **WEDGE** |
| reach out, box height | raised | 0 / 2936 / 7600 / 2961 | -18.4 | 832 | 0.517 | transient |
| hands in, box height | raised | 0 / 3207 / 18329 / 5979 | -19.1 | 1177 | 0.445 | transient |
| **hands in, chest height** | raised | 0 / 3205 / 6754 / 2244 | -18.4 | 2109 | **1.430** | **WEDGE** |
| **lateral sweep** | raised | 0 / 2834 / 7565 / 2217 | -18.4 | 1755 | **1.415** | **WEDGE** |
| **dropout 3/5/8** | raised | 0 / 2887 / 14875 / 4488 | -18.4 | 0 | **1.421** | **WEDGE** |

- **10 of 10 drive the hand into the slab** (7.6-19.1 mm deep, 80-353 N).
- **6 of 10 wedge permanently**, wrist pitch END 1.415-1.430 rad.
- Wrist actuator saturated at its 5 N·m rating on **173-232 of 254 frames**.
- END ~1.42 is identical across the wedged rows. **TR18 checked, not an artifact**: it
  is the wrist pitch joint limit (1.614) minus the pinned command (~0.2) — jammed
  against the stop, exactly as O26. Likewise every locked row reads pelvis z 0.790,
  0.0° pitch and 0.000 m travel because the base is welded.
- **The "raised" approach is equal or worse**: hands-in at box height 27,515
  contact-steps raised vs 15,296 direct; dropout 22,250 vs 11,070. A raise authored in
  *hand* space is not reproduced in *robot* space — it asks for close-in, high hand
  positions, exactly what the 4-DOF IK cannot serve (O19).
- **Coast logic behaves to spec.** Gaps of 3, 5, 8 frames: 191/194 applied, 3 frozen —
  the 3- and 5-frame gaps fully coasted (`max_coast_frames = 5`), the 8-frame gap
  coasted 5 and froze 3. The dropout did not cause its wedge (see the control).

**The control that answers the question.** Same motions, base locked, pickup platform
collision disabled, nothing else changed:

| motion | platform ON: pitch END / verdict / target p50 | platform OFF: pitch END / verdict / target p50 |
|---|---|---|
| hands in, chest | 1.424 / **WEDGE** / 194 mm | **0.001 / ok / 56 mm** |
| lateral sweep | 1.415 / **WEDGE** / 216 mm | **0.001 / ok / 53 mm** |
| dropout 3/5/8 | 1.419 / **WEDGE** / 142 mm | **0.001 / ok / 59 mm** |
| reach out, box height | 0.513 / transient / 102 mm | **0.001 / ok / 37 mm** |
| hands in, box height | 0.394 / ok / 122 mm | **0.001 / ok / 29 mm** |

**Every wedge disappears. The platform is the sole cause.** The torso is not: the
lateral sweep still contacts the torso 1,843 steps at 389 N with the platform off and
does not wedge. And O19 unreachability does not jam the arm on its own — hands-in to
the chest tracks its target to 56 mm with nothing to catch on. (All five platform-off
runs share a pitch max of 0.059 rad — the same start-up transient, the neutral IK seed
settling to home, in every run.)

**The mechanism.** The home hands start below slab height and behind its edge. To get
above the slab they must rise, through a region — close to the body and high — the IK
cannot place them in (O19: 56-131 mm on stepped state). The achieved path comes out
forward and low, under the slab edge; the pad hooks; D2 makes the jam permanent.
Teleop's own mapping loss (section 1) and smoothing lag make it worse than the
scripted case, which is why the scripted fix does not carry over.

**So: structural — not an operator warning, not a training protocol.** An operator
cannot be trained to produce a robot hand path the retargeting will not reproduce.
The options are those O26 already named — restore close-in reach (P2 part 1, the D2
pinned-wrist formulation), collision-aware IK, or change what the hands can hit — plus
one this run suggests and has **not** tested: **start collection with the arms already
above the slab**, so the unreachable raise never has to happen.

### 4. Does the robot stay standing? Yes — but TR15's stated reason is wrong

Base **free**, locomotion policy live: **20 of 20 runs stay up** (min pelvis z 0.717 m,
no falls). The closest call reached **23.9° pitch** (lateral sweep, direct) against the
demonstrator's 25° fall threshold, and the base was **pushed back 0.16-0.41 m** — O17's
recession, now under teleop. A free base frees the hands by retreating, which is why
only one free run (hands-in to chest, raised) wedged permanently. Collection runs
locked, so these are not the collection risk.

**On TR15.** The positive feedback loop cannot form in this path — confirmed — but not
for the reason CLAUDE.md section 9 gives. TR15 says `compute_arm_targets` "anchors at
the *live* shoulder, so the target moves with the robot". It anchors at the **twin's**
shoulder, and the twin's base is never synchronised to the stepped robot, neither in
`run_integrated_combined.py` nor here. The targets are therefore **body-relative and
blind to the stepped base**: no base-state -> arm-command path exists, so there is
nothing to feed back. Same safety conclusion, different mechanism, and a different
consequence: **the target does not follow the robot.** As the free base recedes
0.16-0.41 m, the commanded arm pose is unchanged and the box is simply further away.
CLAUDE.md is untouched; flagged for the closeout.

### 5. What this does NOT cover

- **Real ZED noise** — depth noise, jitter, body-fitting bias, confidence-dependent
  dropouts. One-Euro and the stillness lock saw only clean synthetic signals.
- **True human motion statistics** — the motions are authored, smooth and idealised;
  real demonstrators hesitate, overshoot, correct, and move asymmetrically.
- **Operator timing and reaction** — no human is closing a visual loop. A person
  watching the arm catch the platform might stop or back out; nothing here can.
- **Human limb proportions** — paths were authored in robot proportions on purpose;
  how real proportions distort the retargeted path is unmeasured.
- **The entry point itself** — `run_integrated_combined.py --synthetic` constructs, but
  its UI loop was not run.
- **One spawn** — seed 0, one base placement, one box position.

**O25 stays open.** What is now known: the teleop path's poses are *not* executable
near the pickup platform as collection would run it, and the reason is identified.

### For the closeout

1. **O25 stays open**, stepped half answered: 6/10 permanent wedges base-locked, 10/10
   platform contact, the platform-off control removes every wedge.
2. **O26's mitigation is demonstrator-only.** The staged raise does not survive
   retargeting, so it must not go into the Phase 5 protocol as though it protects
   teleop.
3. **TR15's mechanism statement needs correcting**: targets are twin-anchored and blind
   to the stepped base, not "moving with the robot".
4. **Retargeting loss is now measured**: 0.13 rad mean / 0.55 rad max joint-space,
   concentrated in the elbow; 34 mm p50 / 68 mm p95 in position, the p95 over the 45 mm
   guard.

---

## 2026-09-15 — TELEOP HAZARD: two candidate fixes measured. Neither adopted.

**MEASUREMENT ONLY.** Both flags ship default-off and were verified off after the runs
(`IKConfig.free_wrists = False`, `DemoConfig.hand_platform_filter = False`); with them off,
seed 0 reproduces the adopted demonstrator exactly (palm 34.5481 mm, place 0.0393 m,
196 hand-platform contact-steps, wrist pitch 0.4642 rad). CLAUDE.md and `g1_data/spec.py`
untouched.

The hazard is the O25 result: base-locked teleop near the pickup platform wedges a wrist
permanently in 6 of 10 synthetic motions, and every motion drives the hand into the slab.

**Short version.** Take a third variant, **B′: the hand-platform contact filter scoped to
the PICKUP platform only**. It is the one configuration that removes every teleop wedge and
every hand-platform contact and still passes both gates, 12/12 and 40/40. **Candidate B as
briefed (both platforms) fails the place, 27/40.** **Candidate A (free wrists) fails both.**
It leaves 3/10 permanent wedges and 10/10 contact in teleop, and it drops the gates to 9/12
and 36/40. So A does not make B unnecessary. **The staged raise is still needed under B′**:
without it the gate drops to 34/40.

B′ goes beyond the brief. It exists because B failed, and it is labelled as such everywhere
below.

### Rules held

Stepped model only, no twin residual anywhere (TR16a). Contacts gate on `d.ncon` and
`mj_contactForce` (TR19). Every synthetic motion starts at home. TR18 checked on every
result that came out identical (see B vs B′ teleop, and the B′ vs baseline per-seed diff).

### What was built (all behind default-off flags)

- **`g1_teleop/contact_filter.py`** (new): `apply_hand_platform_filter(model, platforms)`.
  Collision is bitmask-based, so a pair collides iff `a.contype & b.conaffinity` or
  `b.contype & a.conaffinity`. The filter first asserts every colliding geom starts at
  (1,1), then sets:

  | group | contype, conaffinity |
  |---|---|
  | listed platforms | (4, 1) |
  | hands: bodies whose name contains `wrist` or `pad` | (2, 1) |
  | everything else, including box, elbows, torso, floor, unlisted platform | (1, 3) |

  That gives: hand↔platform off; box↔platform on; hand↔box on; hand↔torso on;
  elbow↔platform on; **hand↔hand OFF** (a side effect, see disclosures). It must run
  before `GraspWeld(m)`, which saves the pad bitmasks it toggles.
- **Candidate A**: `IKConfig.free_wrists`. The IK drives all 7 joints per arm. **The task
  point had to change.** A literal 4→7 joint change is degenerate: wrist yaw moves the
  wrist *body* origin 0.000 m/rad, so a wrist-body task cannot use it. A therefore puts the
  second task point on the **palm site** (`mj_jacSite`). In teleop the palm target is
  `wrist + unit(wrist − elbow) · hand_len`, and in `PoseBook.solve` the palm is aimed at the
  goal directly.
- **Candidate B**: `DemoConfig.hand_platform_filter` = `True` (both platforms) or
  `"pickup"` (B′). The harness `Rig(filter_hands=…)` takes the same values.
- **`tools/teleop_fix_candidates.py`**: `teleop A|B|Bp`, `gates base|A|B|Bp|Bpns N lock|pred`,
  `corridor base|A`. JSON goes to `docs/measurements/`.

### The wrist-twist artifact, defined before looking

D2 was adopted because wrist twist made the grasp pose unusable. The operational definition
was fixed in the tool's docstring before any A run and was **not moved afterwards**. At the
first tick the weld is commanded, it is an ARTIFACT if either:

- the angle between the palm-plane normal (the thin axis of the hand mesh) and the
  palm→box direction exceeds **45°** on any seed, or
- any wrist joint sits more than **1.0 rad** from `WRIST_NATURAL`.

| | palm-normal angle at grasp | max wrist offset at grasp |
|---|---|---|
| baseline, 40 seeds | 34.3–37.0° | 0.00 rad |
| A, 40 seeds | 33.9–37.4° | 0.12–0.14 rad |

**By the pre-registered definition, A has no twist artifact at grasp.** Its palms present
exactly as the pinned wrists do, and it grasps *more* accurately.

**The definition was too narrow, and that should be said plainly.** A fails later, at
RELEASE. In the 12-seed trace, wrist pitch reaches −0.69 to −0.82 rad during RELEASE. The
wrist levers the released box over: all 3 of A's 12-seed failures and 2 of its 4 40-seed
failures end with the box at 90° tilt. A grasp-instant metric could not see this. Whether
it is the same phenomenon that motivated D2 cannot be told from here, because D2's
original evidence was on the friction grasp.

### The table

Teleop set = the O25 synthetic motions: 5 motions × 2 approaches, base locked, seed 0.
"Contact" counts hand **and elbow** geoms against the pickup platform. The gates use the
walking demonstrator.

| | baseline | **A** free wrists | **B** filter, both platforms | **B′** filter, pickup only *(beyond brief)* |
|---|---|---|---|---|
| **jams**: teleop permanent wedges | **6/10** | **3/10** | **0/10** | **0/10** |
| teleop transient wedges (>0.8 rad at any time, recovered) | 3/10 | 7/10 | 0/10 | 0/10 |
| teleop clean runs | 1/10 | 0/10 | 10/10 | 10/10 |
| teleop wrist pitch at END | ≤1.430 rad | ≤2.157 rad | ≤0.008 rad | ≤0.008 rad |
| **contacts**: teleop runs touching the platform | **10/10** | **10/10** | **0/10** | **0/10** |
| teleop platform contact-steps | 9,765–27,515 | 1,722–22,754 | 0 | 0 |
| teleop penetration | −7.6 to −19.1 mm | −6.1 to −18.8 mm | — | — |
| teleop wrist saturated frames (of 254) | 173–232 | 61–230 | 3–49 | 3–49 |
| teleop target error, p50 per run | 102–216 mm (direct approach only; raised not tabulated in O25) | 126–306 mm | 37–73 mm | 37–73 mm |
| demonstrator hand-platform contact (40-seed) | 21/40 seeds, ≤514 steps, ≤28.3 mm | 29/40, ≤822, ≤9.2 mm | 0 | 0 |
| **palm error at grasp**, 12-seed | 34.5 mm | **26.8 mm** | 34.5 mm | 34.5 mm |
| **palm error at grasp**, 40-seed | 30.1–36.1 mm | **22.4–29.0 mm** | 30.1–36.1 mm | 30.1–36.1 mm |
| **close-in achieved reach**: corridor cells ≤45 mm (of 40) | **0/40** (min 58, median 89 mm) | **2/40** (min 41, median 59 mm) | not re-run: IK unchanged | not re-run: IK unchanged |
| close-in in teleop: hands-in-to-chest target p50 | 194 mm | 296 / 306 mm | 57 / 68 mm | 57 / 68 mm |
| **12-seed gate** (phase lock) | **12/12** | **9/12** | **9/12** | **12/12** |
| **40-seed gate** (predicate) | **40/40** | **36/40** | **27/40** | **40/40** |
| placement, passing seeds (40-seed) | 0.0316–0.0523 m | 0.0178–0.0922 m | 0.0256–0.0485 m | 0.0316–0.0523 m |
| samples per episode (40-seed) | 694–846, mean 757 | 694–835, mean 769 | 694–846, mean 757 | 694–846, mean 757 |

Notes on the table:

- **Corridor** means palm targets at forward 0.08–0.26 m and z 0.86–0.92, on a 10 × 4 grid.
  The solved pose is applied to the stepped model with the base welded, held 0.5 s, and the
  **achieved** palm error is measured. A helps a little, but 38/40 cells are still over the
  guard. O19 remains.
- **B and B′ teleop rows are identical.** TR18 checked, and this is not an artifact: the
  teleop rig parks the robot at the pickup platform, 1.5 m from the goal platform, so the
  goal-platform filter has nothing to act on there. It is not independent evidence for B.
- **Close-in reach in teleop gets *better* under B/B′** (target error 194 → 57 mm) only
  because nothing blocks the arm. It is still over the 45 mm guard. Removing the obstacle
  does not create reach.

### Candidate A in detail

- **Teleop:** wedges 6 → 3, but the three that remain are worse (END 1.12, 1.58, 2.16 rad).
  Contact is unchanged: 10/10 runs, roughly the same contact-steps except the lateral sweep.
  Freeing the wrist does not stop the hand hooking the slab. It gives the wrist more range
  to be driven into, still against a 5 N·m actuator.
- **12-seed:** 9/12. Seeds 0, 3 and 9 fail PLACE(xy) with the box tipped 90°: the release
  lever described above.
- **40-seed:** 36/40. Seeds 11 and 35 tipped 90° (place 0.50, 0.49 m); seeds 2 and 24 just
  over the limit (0.104, 0.121 m). One passing seed places at 0.092 m. Placement spread
  roughly doubles.
- A also puts demonstrator hands on the platform in more seeds (29/40 vs 21/40), though
  shallower.

**Is D2 still justified?** Its *stated* reason (the grasp pose is unusable) does not
reproduce under the weld. Grasp presentation is unchanged and palm error improves
7–8 mm. But freeing the wrists costs the place (4/40, 3/12) and does not fix the teleop
hazard. D2 stays justified on the evidence here, **for a different reason than the one
recorded in CLAUDE.md §7**. A release-phase wrist pin might recover the place; that was
**not tested**.

**If A were ever adopted, the spec work is:**
- `a_left_wrist_yaw` and `a_right_wrist_yaw` (dims 6, 13) stop being hard-constant.
  `CONSTANT_ACTION_DIMS` / `_AUDITED_CONSTANT_DIMS` = (6, 13, 14, 15, 16, 18) would shrink,
  provisionally to (14, 15, 16, 18). The load-time assertion would catch the stale mask.
- The wrist roll/pitch comment ("bit-identical time-series in every episode") would no
  longer be true.
- **`SPEC_VERSION` bump**. Its own rule is "a mask changed", so 1.1.0 → 1.2.0 at least.
  `assert_spec_version` refuses any mismatch, so the level is cosmetic.
- The constant-dimension audit and the velocity-dim measurement must be re-run on 12 A
  episodes, and the mask re-derived from measurement, not guessed.
- `test_spec.py` needs updates. CLAUDE.md D2 and D3 rows change (the task becomes
  elbow + palm, not elbow + wrist).
- **Estimate:** about 3 h of spec/test/doc edits plus about 1.5 h of compute for the audit
  and both gates, so about one working day. That excludes fixing the release twist, which
  is unscoped and blocks it anyway.

### Candidate B in detail, and why B′

- **Teleop:** 0 contacts and 0 wedges in all 10 runs; wrist pitch END ≤0.008 rad. The torso
  contact in the lateral sweep remains (1,683 / 1,838 steps, the O24 kind, as in the O25
  platform-off control). It is not the platform and does not wedge.
- **B, both platforms, 12-seed: 9/12.** Seeds 0, 3 and 9 have the box off the goal platform
  (place 0.64–0.82 m). **Mechanism:** in the adopted configuration the hand comes to rest
  *on* the goal platform at release (palm z ~0.79) and the box settles. With that contact
  filtered, the hand drops through the goal slab (palm z 0.72 against a top of 0.75) and the
  box is flung.
- **B, 40-seed: 27/40.** 13 failures:
  - 10 PLACE(xy): 6 with the box off the platform (0.42–0.81 m), 1 tipped at 0.154 m, and
    3 marginal at 0.100–0.106 m (one of those tipped 88.5°);
  - 3 PLACE(upright), tipped 87–90° inside the xy limit.
- **B′ = the filter on the pickup platform only.** The goal platform keeps its hand
  contact, and the teleop hazard is at the pickup platform anyway. **12-seed 12/12, 40-seed
  40/40.**

**Box behaviour under B′, measured as a per-seed diff against baseline (40-seed, predicate
lock):**

- The **19 seeds with zero baseline hand-platform contact are identical** to baseline on
  every metric (to 1e-9). The **21 seeds with contact differ slightly.** This is the TR18 check: the
  filter changes exactly the episodes it should and nothing else.
- In those 21 seeds, placement moves by ≤5.9 mm (max: seed 4, 0.0395 → 0.0337 m). Palm error
  at grasp is unchanged to 0.01 mm.
- **Rests on both platforms:** resting 40/40, the same as baseline.
- **Tilt unchanged:** max 10.9° on seed 20 in both baseline and B′. 0.8° on seed 24 in both.
  0° elsewhere.
- **No tunnelling:** the box centre never goes lower than 2.2 mm below its resting height
  over either platform. Baseline is the same (−2.2 mm), and this is ordinary resting
  penetration.

**The staged raise is still needed under B′.**
- **12-seed phase lock: 12/12.** On its own this would say "not needed". **It is wrong.**
- **40-seed predicate: 34/40.** Seeds 18, 21, 23, 25 and 37 fail GRASP (palm 864–989 mm):
  the box is gone before the grasp. Seed 3 just misses the place (0.102 m).
- **Mechanism, traced on seeds 18 and 21:** the joint-space reach sweeps the hands up from
  under the slab (palm z 0.60 → 0.94). With the slab filtered, nothing stops them, and the
  right pad strikes the box at i=2275 during REACH, because **hand↔box contact is still
  on**. Seed 18's box ends on the floor (y 0.54). Seed 21's is thrown to x 2.20.
- The B′ control on seed 18, with the staged raise, touches the box first at GRASP and
  succeeds.
- So the staged raise now protects the **box**, not the wrist.

### What now passes through what, under B′, honestly

1. **Both hands pass through the pickup platform slab.** That is every geom on a body whose
   name contains `wrist` or `pad`, including the wrist meshes. This is unphysical. **How deep
   the teleop hands go was NOT measured.** With contacts off there is no contact distance,
   and the point proxy I added (palm site below the platform top while over its footprint)
   **cannot tell "inside the slab" from "under it"**. It reads −130.4 mm in *baseline* too,
   where the hands demonstrably do not penetrate. An earlier in-session reading of that
   proxy as pass-through depth is withdrawn.
2. **Hands pass through each other.** Hand↔hand contact is off as a side effect of the
   bitmask scheme. No synthetic motion was checked for hands crossing, so whether that ever
   happens in the set is **unmeasured**. Fixable with a separate bit per hand if needed.
3. **Still collides:** elbows, forearms above the wrist, shoulders and torso with the pickup
   platform (elbow-platform contacts are counted in the teleop set: 0); hands with the box,
   torso and goal platform; box with both platforms.
4. **New teleop failure mode, not yet tested in teleop:** an operator whose hands come up
   through the slab can hit the box from below and knock it off. That is exactly the Bpns
   mechanism. The teleop set does not record box displacement, so this is **inferred from
   the demonstrator, not measured under teleop**.
5. **It is a simulation-only relaxation of the task.** Demonstrations and evaluation must use
   the same filter, or the policy is trained in one world and scored in another. It is also a
   new deviation: platform contact is removed as a possible failure. It needs a CLAUDE.md §7
   row and a limitation if adopted.
6. **No spec change is needed** under `SPEC_VERSION`'s own rule. No dimension, mask, source or
   clip moves. The recorded physics differ from any baseline-configuration data, but none
   exists yet.

### Recommendation

**Take B′, keep the staged raise, do not take A.**

- B′ is the only candidate that removes the hazard. It takes teleop from 6/10 wedges and
  10/10 contact to 0 and 0, and leaves the demonstrator's gates at 12/12 and 40/40. The only
  per-seed changes are ≤6 mm placement shifts in the episodes that used to touch the
  platform.
- **A does not make B unnecessary.** It halves the wedges without removing a single contact,
  and it breaks the place.
- **Wanting both is not supported either.** A's one real gain, 7–8 mm better palm error, is
  not needed: baseline is already inside the 45 mm guard. A's close-in reach gain (0 → 2 of
  40 cells) does not close O19.
- **B as briefed should not be taken.** Filtering the goal platform removes the support the
  place depends on.
- **Before adopting B′, it needs:**
  - a teleop run that records box displacement (item 4 above);
  - a hands-crossing check (item 2);
  - wiring into the recorder, evaluation and `run_integrated_combined.py` so every consumer
    sees the same world.

Throwaway diagnostics: scratchpad `bpns_diag.py`. Results: `docs/measurements/`
`teleop_{A,B,Bp}.json`, `gates_{base,A,B,Bp,Bpns}_pred_40.json`,
`gates_{A,B,Bp,Bpns}_lock_12.json`, `corridor_{base,A}.json`.

---

## 2026-09-15 — B-prime ADOPTION attempted as a pair exclusion: validated, then REVERTED on the strict regression rule

**Outcome.** B-prime was implemented as `<contact><exclude>` body pairs with a contract
that makes a recording/evaluation mismatch raise. Both gates pass: **12-seed phase lock
12/12**, **40-seed predicate 40/40**. All three outstanding checks were run.

The instruction was "if either gate regresses on ANY measure, REVERT". Four measures
moved past the baseline envelope, all by very small amounts, so **the adoption is
reverted and nothing was fixed.**

Git history on branch `adopt-bprime`:

| commit | what |
|---|---|
| `3e89408` | checkpoint before starting |
| `827d8bf` | the full attempt: code, tests, validation tools, JSON results |
| `0144e0a` | revert of `827d8bf` |

The working tree now matches the checkpoint exactly: `git diff 3e89408` is empty and the
spec tests pass 43/43. `git revert 0144e0a` re-applies the adoption as-is.

This section follows the "2026-09-15 — TELEOP HAZARD" candidate section above. The brief
called it the 2026-09-14 section, but it is dated 2026-09-15.

**The most important finding is not the revert.** Check (b) shows that B-prime's
"clean" teleop result hid a new failure mode. With the slab no longer stopping the hands,
they reach the box through it:

- it moves in **14 of 14** teleop motions (median ~100 mm);
- it is **knocked clean off the platform in 3 of 14**, all on the trained "raised" approach.

The earlier candidate report never measured box motion under teleop, so its "clean"
verdict was incomplete. This belongs in the adoption decision whatever is done about the
tiny regressions.

### The regressions that triggered the revert

Comparisons are strict, with criteria fixed in `tools/bprime_compare.py` (in `827d8bf`)
before the adopted results were read. The baseline is the same instrumented harness with
the exclusion stripped, which reproduces the checkpoint exactly: seed 0 gives palm
34.5481 mm, place 0.0393 m, 196 hits and wrist 0.4642 rad, identical to the adopted state.

| gate | measure | baseline | adopted | size |
|---|---|---|---|---|
| 12-seed | max base pitch | 10.6541° (seed 4) | 10.7697° (seed 4) | +0.116°, one seed |
| 12-seed | min box-corner gap, any phase | −12.2075 mm | −12.2101 mm | 0.003 mm deeper |
| 40-seed | max carry drift | 2.7765 mm (seed 7) | 2.7785 mm (seed 7) | +0.002 mm |
| 40-seed | min box-corner gap, box unwelded | −9.5822 mm (seed 8) | −9.6465 mm (seed 28) | 0.064 mm deeper |

- The 12-seed box-gap figure is the **welded** box pressed into the goal slab during
  LOWER. Baseline does the same by up to 15.3 mm; it is not resting sink.
- The 40-seed unwelded case is resting sink. Seed 28 alone went 0.24 mm deeper than its
  own baseline.
- All four moved in seeds whose baseline episode had hand-slab contact (seed 4: 97
  contact-steps). Removing that contact changes those trajectories; nothing else moved.
- **Not regressions:**
  - pass counts, falls, wedges, lock fallbacks;
  - placement and palm-error envelopes (identical);
  - resting 12/12 and 40/40;
  - max box tilt (identical, 10.89°);
  - episode length (max identical; mean 757.05 → 756.77);
  - pre-grasp box displacement (identical).

**Whether a 0.1° / 0.06 mm envelope move should count is Charles's decision, not this
session's.** Strict was the literal instruction. A tolerance policy would have passed.

### 1. Implementation (all in `827d8bf`, all reverted)

- **`scene.xml`**: six excludes against `platform_pickup`: `{left,right}_wrist_pitch_link`,
  `_wrist_yaw_link` and `_pad`.
- **Deviation from the brief, measured.** The brief named `wrist_yaw_link` and the pads.
  That set was run on the teleop motion set first. It left **wrist_pitch_link ↔ slab
  contact in 10/10 motions** (4–2,414 contact-steps), though no wedges. The pitch link
  was therefore added. `wrist_roll_link` was not: it touched the slab in no run under any
  set (none / yaw+pad / all wrist bodies), so excluding it would lose fidelity for nothing.
  The earlier bitmask B-prime had excluded the roll link too.
- **`TeleopConfig.contact = ContactConfig(hand_pickup_exclusion=True)`**, default on. With
  False, `contact_contract.load_model` strips the excludes through `MjSpec` before
  compiling. The stripped model differs from the default only in name-table bookkeeping.
- **`g1_teleop/contact_contract.py`** — `contract_of(model)` is read from the
  **compiled** model:
  - it decodes `exclude_signature`. The layout `(min_body_id << 16) + max_body_id` was
    measured on this build, not assumed;
  - it adds a bitmask tag, so a contype/conaffinity filter layered on top is also caught.
- **Loaders switched** to `load_model(cfg)`: `scripted_demo.run_episode`,
  `run_integrated_combined.py`, `tools/teleop_physics_check.Rig`, and the corridor probe.
- **`tools/teleop_fix_candidates.py`**: every candidate tag loads with the exclusion
  stripped, so the candidate numbers stay reproducible.
- **Tests** in `g1_data/test_contact_contract.py`: **13/13**. Spec tests stayed 43/43.

### 2. Where the setting lives and how a mismatch is caught (requirement 3)

1. **The setting is `TeleopConfig.contact`.** That is the config the demonstrator, the
   teleop entry point, `reset_episode`, and the future recorder and evaluator all take.
   The pairs themselves are in `scene.xml`, so any loader gets the default.
2. **`reset_episode` raises** (`ContactContractMismatch`) if the compiled model's exclude
   table or bitmasks do not match `cfg.contact`. It is the one place every recording and
   evaluation episode starts. **Live**, and tested in both directions: an excluded model
   with an off config raises, and an unexcluded model with an on config raises.
3. **`EpisodeStart.contact_contract` carries the contract string**, and
   `assert_recorded_contract(recorded, model)` raises when a dataset's value differs from
   the evaluation model's, including a missing value. **This half is a hook only.** The
   recorder and evaluator do not exist yet, and nothing forces them to call it. Tested to
   raise, not enforced.

### 3. The three checks

**(a) Hands crossing.** New `hands_cross` motion (hands sweep across the midline into each
other above the box), base locked.

| config | hand↔hand contact-steps (direct / raised) | max force |
|---|---|---|
| adopted (pair exclude) | **1,999 / 2,171** | 109 / 91 N |
| old bitmask B-prime | **0 / 0** | — |
| baseline | 0 / 0 | — (the hands never meet: the arm wedges on the slab first, target error 269 mm) |

- Hand↔hand contact also occurred incidentally in `hands_in_chest` direct (47 steps) and
  `rise_under_box` raised (245 steps).
- Every Bp run reads 0. **Hand↔hand contact survives the pair exclusion, and the check can
  fail:** it fails on the old bitmask, which is what that approach silently disabled.
- Static proof, independent of IK: the right hand's root body was shifted onto the left
  hand. Contacts are present under the exclusion and absent under the bitmask. The same
  method shows hand↔goal platform and hand↔box contacts present, wrist_roll↔pickup
  present, and hand↔pickup absent when on and present when off.
- **In the gates:** hand↔goal-platform contact occurs in every seed, 299+ steps and up to
  117.6 N, as at baseline. Hand↔hand contact is 0 in all 52 demonstrator episodes, in
  both baseline and adopted.

**(b) Box displacement under teleop, before any grasp.** This is the finding that matters.
Base locked, 14 motions, including the new `rise_under_box` (hands forward under the slab,
beneath the box footprint, then straight up).

| motion | approach | adopted: max disp mm / tilt° / off platform | baseline (exclusion stripped) |
|---|---|---|---|
| reach_out_boxh | direct | 99 / 6 / no | 0.1 / 0 / no |
| hands_in_boxh | direct | 136 / 34 / no | 0.1 / 0 / no |
| hands_in_chest | direct | 65 / 23 / no | 24 / 11 / no |
| lateral_sweep | direct | 159 / 57 / no | **1147 / 177 / YES** |
| hands_cross | direct | 11 / 1 / no | 127 / 41 / no |
| rise_under_box | direct | 184 / 12 / no | 0.1 / 0 / no |
| dropout_3_5_8 | direct | 101 / 24 / no | 82 / 17 / no |
| reach_out_boxh | raised | 80 / 20 / no | 0.1 / 0 / no |
| hands_in_boxh | raised | **876 / 179 / YES** | 0.1 / 0 / no |
| hands_in_chest | raised | **876 / 179 / YES** | 27 / 12 / no |
| lateral_sweep | raised | **875 / 179 / YES** | 117 / 66 / no |
| hands_cross | raised | 10 / 2 / no | 124 / 38 / no |
| rise_under_box | raised | 197 / 24 / no | 0.1 / 0 / no |
| dropout_3_5_8 | raised | 96 / 22 / no | 0.1 / 0 / no |

- **Adopted:** the box moves more than 1 mm in **14/14** motions, 10–197 mm when it stays
  on, and is **knocked off entirely in 3/14**. It ends displaced 6–190 mm and tilted up to
  21° when it stays on.
- **Baseline:** the box moves in 7/14 and is knocked off in 1/14. The slab stops the hand,
  which is also what jams the wrist.
- **All three knock-offs are on the "raised" approach**, the path an operator would be
  trained to use. TR18 checked: the identical 876.4 mm on two motions is not an artifact.
  The raised motions share their home→up→out prefix (every motion's first point is at the
  same box-face y), and the box leaves the platform during that shared prefix, before the
  motions differ.
- **Worst case, `rise_under_box`:** 184–197 mm, stays on the platform.
- **So yes, an operator can ruin an episode.** B-prime trades a permanent wrist jam for a
  pushed or knocked-off box. That is recoverable by reset but equally episode-ending, and
  **far more frequent**: 14/14 motions disturb the box, against 6/14 wedging at baseline.
- **Unmeasured:** whether a nudged-but-recovered box contaminates demonstrations that go on
  to succeed.

**(c) Pass-through depth, replacing the withdrawn site-height proxy.**

Definitions (`tools/contact_measures.py`, in `827d8bf`):
- **Primary:** a shadow copy of the scene without the exclusion is posed at the live qpos
  (`mj_kinematics` + `mj_collision` only). MuJoCo's own narrow phase reports the suppressed
  hand↔slab contacts. **Depth = −contact.dist**, the minimum translation that would
  separate the hand geom's collision hull from the slab. A hand *under* the slab reads 0,
  which is exactly what the old proxy could not do. Duration comes from probes every
  10 ms, as a total and as the longest continuous run.
- **Cross-check:** hand mesh vertices (box corners for pads) are tested inside the slab
  box. This depth saturates at the slab half-thickness, 20 mm, by construction.

Validation:
- **Shadow depth equals live contact depth to 0.000 mm** on every probe where the contact
  is live: 10,655 probes over the stripped teleop runs, 162 in the stripped gates.
- In the stripped teleop runs it reproduces O25's contact depths, −7.6 to −19.1 mm.
- The vertex check reads 19.7–20.0 mm whenever the shadow reads 60+ mm. That confirms
  *inside*, not under.
- One claim is withdrawn: I expected "vertex inside but no shadow contact" to be
  impossible. It is not: 10 of 12,082 adopted teleop probes. The magnitude was not
  recorded; presumably grazing contacts.

| where | max depth | how long | where in the episode |
|---|---|---|---|
| teleop, adopted, 14 motions | **60.4–69.6 mm** | 0.05–7.29 s total per ~8.6 s stream, longest continuous **5.59 s** | pads ≤69.6 mm, wrist_yaw_link ≤55.6 mm, wrist_pitch_link ≤42.2 mm |
| demonstrator, adopted, 12-seed | ≤65.7 mm, 12/12 seeds | ≤0.26 s per episode, longest 0.13 s | REACH only |
| demonstrator, adopted, 40-seed | ≤65.5 mm, 20/40 seeds | ≤0.26 s, longest 0.25 s | REACH only |

- For comparison, baseline live penetration is ≤19.1 mm in teleop and ≤16.3 mm in the
  demonstrator.
- **Disclosure sentence:** with the exclusion, a hand can sit up to **70 mm** inside the
  pickup slab (it would have to move 70 mm to clear it), for up to **5.6 s continuously**
  under teleop. The scripted demonstrator does so briefly during REACH (≤0.26 s, ≤66 mm).

### 4. Validation

**Gates, adopted vs stripped baseline.**
- Palm error, placement, tilt and episode-length envelopes are identical. The four
  exceptions are in the regression table above.
- Per-seed changes occur only in seeds with baseline hand-slab contact: placement within
  ±5.9 mm, pitch within ±0.66°. The other seeds are identical.
- Hand↔pickup contact is 0 in every adopted seed. The pickup platform's only remaining
  robot contact is the **pelvis** against the slab edge: 582 steps adopted vs 578 baseline
  at 12 seeds, 1,381 vs 1,380 at 40.

**Box behaviour.**
- Rests 12/12 and 40/40.
- Tilt identical (max 10.89°, seed 20, both).
- Pre-grasp box displacement in the demonstrator identical (max 1.87 mm).
- Sinking: see the regression table. Resting-box corner gaps are −3.9 to −9.6 mm, against
  baseline −3.9 to −9.6 mm.
- An earlier version of the sink measure counted box corners outside the platform
  footprint and read −12 mm in baseline. It was fixed before any comparison was made.

**Staged raise still required: adopted without it, 34/40** (predicate). Seeds 3, 18, 21,
23, 25 and 37 fail:
- seed 3 on PLACE(xy), 0.102 m;
- the other five on GRASP, with the box displaced **887–1,011 mm before the grasp** and
  hands inside the slab during REACH.

This is the same failure set as the bitmask candidate (Bpns 34/40): hands rising through
the slab knock the box off. The 12-seed phase-lock gate alone would have said "not needed".

### For the closeout (not written here, per instruction)

- **The adoption decision is open again.** Decide whether the strict any-measure rule
  should carry a tolerance. If re-adopted, `git revert 0144e0a`. Weigh check (b) either way.
- **If adopted, it needs:**
  - a new deviation row: a simulation-only relaxation, applying to collection **and**
    evaluation;
  - a limitation: hands ≤70 mm inside the pickup slab for ≤5.6 s continuously, and box
    disturbance by the operator in 14/14 teleop motions.
- **D2's rationale is stale:** the pinned wrists protect the PLACE, not the grasp pose.
- **TR15's mechanism is stale:** the loop cannot form because the twin's base is never
  synced, not because the target follows the robot.
- **The recorded-contract check is a hook only** until the recorder and evaluator call it.

---

## 2026-09-15 — Teleoperated grasp made physically possible in run_integrated_combined.py

**Trigger.** A live camera test confirmed O17 on the teleop path. The robot walks and
mirrors the operator's arms but cannot grasp: the free base settles at the 0.47–0.59 m
attractor while the arms serve 0.28–0.36 m, so the palms never reach the box and
`GraspWeld` correctly refuses.

**Result.** With the changes below, a synthetic operator stream running through the
**unmodified teleop stack** does all four steps on the stepped model:

1. the base locks on the predicate;
2. the weld engages through the geometric gate;
3. the base releases on the predicate once the box is lifted;
4. the robot stands holding the box.

Headless, seed 0, `--start-standoff 0.32`.

The same run with B-prime OFF wedges a wrist at 1.42 rad (the O26 jam) and never welds.

**Scope held to the brief.** No episode loop, phase machine, recorder or PoseBook: the
human (or the synthetic stream) provides the arm trajectory. CLAUDE.md and
`g1_data/spec.py` untouched.

### Commits on `adopt-bprime`

| commit | what |
|---|---|
| `080237b` | safety commit: the keypoint recorder work, before starting |
| `51fc1d7` | **cherry-pick of 827d8bf (B-prime)**, message corrected |
| (this change) | see below |

B-prime was reverted earlier today in `0144e0a` on the strict any-measure gate rule:
- 12-seed: max base pitch +0.116°;
- 40-seed: max carry drift +0.002 mm, and box sink ≤0.06 mm deeper.

It is re-adopted here **by instruction**. Those same sub-millimetre envelope moves against
the pre-B-prime baseline therefore come with it. The gate check below compares against
the B-prime results, which is the configuration now in force.

### The five changes

**1. Base lock (D12), driven by the demonstrator's own predicate.**
- `LockPredicate(PlatformGeometry.resolve(model), LockConfig())`, updated every
  `spec.PHYSICS_STEPS_PER_TICK` = 20 physics steps (25 Hz) on
  `SpecLayout.build_state(..., sync=False)`. That is the same predicate, the same
  thresholds, the same rate and the same `sync=False` as `scripted_demo.run_episode`.
- The lock and release edges follow `pred.locked` against `BaseLock.locked(data)`,
  exactly as the demonstrator does.
- **While locked:**
  - the locomotion policy is not queried;
  - the velocity/heading hold is skipped;
  - the legs are PD-held at `DEFAULT_ANGLES`.
- **On release:**
  - `BaseLock.release(..., policy=policy)` zeroes the LSTM state;
  - `action` is zeroed and `target_leg_pos` set to `DEFAULT_ANGLES`;
  - the station-keeping anchor is reset to where the base is.
- **Manual abort** (key `u`, headless fixture `--abort-at`) is the only operator input
  that touches the lock. There is deliberately no key to force one. Every abort is logged
  with the predicate terms.
- **The abort needed a re-lock inhibit, and it took two attempts. Both were measured, not
  assumed.**
  - Without an inhibit, a still robot re-locks about 1 s after an abort.
  - First try, "clear the inhibit when `lock_ok` goes false": it cleared after 0.12 s.
    The release jolt breaks the stillness term at once.
  - Second try, "clear when the lock geometry (fwd / lat / heading) fails": it cleared
    after 0.24 s. The release transient alone swung heading to −6.1° and lateral to
    −35 mm, against 5° / 50 mm limits.
  - **Adopted:** the inhibit clears only when the robot leaves the geometry band by a
    margin — standoff ±0.05 m, lateral +0.05 m, heading +10°. Those margins take a
    deliberate step or turn.
  - Verified: after an abort at 3.0 s the robot stayed unlocked, marching in place, until
    the weld engaged at 9.5 s. At that point the lock target became the goal platform,
    as the predicate defines.
  - The margins gate **only** the abort inhibit, never the lock itself.

**2. TR17 pad fix.** `ctrl[pad_ctrl]` was driven with `grasp_cmd`. It is now held at
**zero**, and the command goes only to `GraspWeld.update`, as in the demonstrator.
Weld engage and release are logged with all four gate measurements.

**3. B-prime merged**, default ON, toggleable at runtime with key `b` (`--bprime-off` to
start off).
- `nexclude` is fixed at compile time, but `exclude_signature` is a live array the
  collision filter reads every step.
- `contact_contract.set_hand_pickup_exclusion` writes signature 0 (world|world, two
  static geoms that never collide) into every slot for OFF, and the six real signatures
  back for ON.
- Measured on a hand posed inside the slab: 0 contacts ON, 2 OFF, 0 ON again.
- `contract_of` skips the switched-off slots, so a model toggled OFF reports exactly the
  contract of a model compiled without the exclusion. Anything recorded after a toggle
  carries the physics it was actually recorded under.
- A model compiled without the exclusion refuses a runtime ON.
- New test: `test_runtime_toggle_switches_the_physics_and_the_contract`. Contract tests
  are now 14/14.

**4. NaN confidence in `ZEDSource._select_best_body`.**
- **The bug:** the score was `np.mean` of the six arm confidences. One NaN made it NaN,
  `NaN > -1.0` is False, and a body with six valid arm keypoints was silently discarded.
- **Found on real data:** the first recorder take, 160/160 frames, where body fitting
  filled the right elbow and both wrists with finite positions but NaN confidence.
- **Now:** `nanmean` over the finite confidences, and 0.0 when all six are NaN (which
  still beats the −1.0 floor).
- The NaN-*keypoint* rejection (TR6's only surviving guard) is unchanged.
- Checked on fake bodies:

  | body | selected? |
  |---|---|
  | partial NaN confidence | yes |
  | all-NaN confidence | yes |
  | NaN wrist keypoint | no |
  | two bodies | the higher `nanmean` |

- **Recorder follow-on:**
  - `classify` asserts the old rejection can no longer happen;
  - new recordings carry `meta["selector"] = "nanmean-2026-09-15"`;
  - status `arm_conf_nan` stays defined, so earlier recordings still load. Their
    `mode="zed"` replay reproduces the OLD selector's decision.
  - Self-test updated: it now requires 0 `arm_conf_nan` frames.

**5. Operator overlay** (right panel, colour-coded; rendered offline and inspected in
three states — free with the gate blocked, locked and welded, locked with the gate open):
- **BASE LOCKED** (green) / **BASE FREE** (amber), and "re-lock inhibited" in red after
  an abort.
- **When free:** the predicate's lock terms, each green or red — fwd in [0.26, 0.40],
  lat, heading, stillness over one gait period.
- **When locked:** what will release it — box lift vs 0.055 m while welded, or "placed
  at goal and hands withdrawn".
- **STANDOFF** |box − base| in xy against [0.28, 0.36], IN BAND / OUT.
- **GRASP** cmd, and WELDED / GATED / open.
- **The weld gate conditions, one [OK]/[X] line each:**
  - L palm-box ≤ 0.16;
  - R palm-box ≤ 0.16;
  - opposition ≤ −0.50;
  - separation in [0.12, 0.30].
- **Status line:** `BLOCKING: <the failing ones>`, or "GATE OPEN – press g", or "weld
  engaged".
- **WRIST** max |qpos − ctrl| over the six wrist joints with the joint name, plus pitch
  on its own: amber at 0.5 rad, red **WEDGE** at 0.8 rad of pitch (TR23).
- **B-PRIME ON/OFF.**

### Headless fixtures (for validation only; none is a collection mode)

- `--synthetic grasp`: new `synthetic_source.grasp_lift_frames`. The path, per hand, in
  the pelvis frame with the robot's own limb lengths:
  hold home 5 s → rise beside the body → out → down to the grasp point → hold (grasp
  command on) → lift 0.20 m → hold.
  - The grasp point (hand 0.09 m behind the box centre, 0.13 m to the side, 0.04 m up)
    came from a probe on the kinematic twin. That only picks a candidate (TR16a); the
    stepped run is the verdict.
  - On the stepped model it closed the gate at palms 0.131 / 0.130 m from the box,
    opposition −0.88, separation 0.253 m.
  - Palms 0.13 m lateral sit ~37 mm outside the box faces, so the gate closes without
    pushing the box.
  - A 0.12 m lift (the first attempt) raised the box only 48–59 mm, not enough for the
    0.055 m release. 0.20 m raised it 89–129 mm.
- `--headless`: no window, no renderer, no wall-clock pacing. `SimClockGrabber` pulls one
  frame per 17 physics steps (29.4 Hz of simulated time) synchronously, so the stream
  cannot be drained by a fast loop.
  - `SyntheticSource` gained `fps` for the windowed synthetic mode. Previously a
    `FrameGrabber` thread would drain a synthetic stream in milliseconds and the loop saw
    only its last frame.
- `--start-standoff S` starts the base S behind the box, head-on. `--seconds`,
  `--abort-at`, `--bprime-off` as named.
- Positional `which` and `seed` are unchanged; argument parsing moved to argparse.

### Validation

**Headless runs**, all `keyboard --synthetic grasp --headless --start-standoff 0.32`:

| run | lock | weld | release | wrist | after |
|---|---|---|---|---|---|
| seed 0, B-prime ON | 0.96 s, standoff 0.327, lat +0.003, head +0.5° | ENGAGED 9.49 s (L 0.131, R 0.130, opp −0.88, sep 0.253) | **predicate, 12.72 s**, box_lift 0.089, welded | ≤0.005 rad | stands, pelvis z 0.760–0.779, base recedes to 0.40 m once free (O17), box stays welded 54–129 mm up |
| seed 0, abort at 3.0 s | 0.96 s | ENGAGED 9.49 s with the base free, standoff 0.320 | none by predicate (inhibit held; no re-lock) | ≤0.005 | box lift 0.11–0.12 m |
| seed 0, B-prime OFF | 0.96 s | **never** (L 0.345, R 0.213, sep 0.526) | none | **1.42 rad — wedged** | — |
| seed 3, B-prime ON | identical to seed 0 to the printed digit | | | | |
| seed 3, B-prime OFF | 0.96 s | never | none | 1.42 rad | differs from seed 0 OFF (L 0.290) |

- **TR18 on the identical seed-3 run: explained, not an artifact.** `--start-standoff`
  places the base relative to the box, so the robot-relative problem is identical unless
  something touches the platform, whose position relative to the robot does differ
  between seeds. Only the B-prime-OFF runs touch it, and only they differ.
- **Consequence:** the headless test covers one relative configuration, not two seeds.
- Why ~0 wrist deviation is plausible: the palms are not touching the box, and 0.4 kg on
  a 500 N·m/rad servo is ~0.001 rad. The demonstrator's 0.55 rad came from pad contact.

**Tests:** spec 43/43, contact contract 14/14, keypoint recorder self-test PASS.

**Scripted gates:** **unchanged — byte-identical to the committed B-prime results.**
`tools/bprime_validate.py gates adopted 12 lock` and `... adopted 40 pred` rewrote
`docs/measurements/bprime_gates_adopted_{lock_12,pred_40}.json` (timestamps 14:05 and
14:14), and `git diff` on both files is empty.

| | 12-seed, phase lock | 40-seed, predicate |
|---|---|---|
| result | **12/12** | **40/40** |
| palm error | 34.54–34.55 mm | 30.09–36.15 mm |
| placement | 0.0377–0.0429 m | 0.0316–0.0523 m |
| carry drift | 2.43–2.79 mm | 2.41–2.78 mm |
| max pitch | 8.37–10.77° | 6.73–14.14° |
| samples | 1278 | 694–846 |
| falls / wedges / fallbacks | 0 / 0 / 0 | 0 / 0 / 0 |
| resting | 12/12 | 40/40 |

Expected: nothing in the demonstrator's path changed after the cherry-pick. The changes
touch `ZEDSource`, `run_integrated_combined.py`, `synthetic_source.py`, the recorder, and
a contract-string helper whose output is unchanged for a model that is not toggled.

### What is NOT validated

- **The windowed path was never opened.** The overlay drawing function was rendered
  offline in three states and inspected, and everything else in the loop is shared with
  the headless run. But the `cv2` window, key handling (`u`, `b`, `g`) and the renderer
  were not exercised in this session; the headless fixture calls the same abort function
  the `u` key does.
- **No real operator.** A live operator must walk the robot into the lock band
  (fwd 0.26–0.40, |lat| ≤ 0.05, |head| ≤ 5°) and then stand still for about 1 s; the
  overlay shows which term is failing. `--start-standoff` skips that walk and is a
  fixture only.
- **Synthetic hand paths are idealised.** Real retargeting loss (0.13 rad mean, O25) and
  ZED noise can put a palm outside the gate that this stream closes with ~30 mm to spare.
- **B-prime's teleop box-disturbance finding stands** (14/14 motions disturb the box,
  3/14 knock it off; NOTES 2026-09-15 B-prime adoption section). This path was chosen to
  avoid it — hands rise beside the body — and a live operator's may not.
- **Existing behaviour left unchanged, flagged:** the loop calls `controller.step` only
  when a frame HAS keypoints. An empty frame never reaches the coast logic, so arms hold
  indefinitely on a dropout instead of freezing after `max_coast_frames`, and the
  recorder analysis assumes the controller definition. Not in this brief.

### For the closeout (not written here)

- D12 now applies to teleoperated collection too: same predicate, manual abort only.
- A new deviation row for B-prime (simulation-only relaxation, collection AND evaluation).
- D2's rationale protects the place, not the grasp pose; TR15's mechanism is the unsynced
  twin base (both carried over from earlier today).
- The `_select_best_body` NaN-confidence bug, found by the recorder, is fixed.

---

## 2026-09-15 — Teleop overlay split into a piloting view and a diagnostic view

The overlay built earlier today had grown to ~20 lines across two panels. An operator
piloting with both hands up in front of the camera cannot read that. It is now two modes,
toggled with **`o`**, **MINIMAL by default**, and the choice is remembered for the rest of
the session (a variable, not a file: a restart is MINIMAL again).

Nothing outside the drawing changed: the headless grasp run reproduces the previous event
times exactly (lock 0.96 s, weld 9.49 s, release 12.72 s), and both scripted gates are
unchanged.

### MINIMAL — the default, at most four lines, large (scale 1.0), top-left

| line | content |
|---|---|
| 1 | **grasp state as one line and one colour**: `HELD` (green), `READY - press g` (green), or one ACTION in amber |
| 2 | `BASE LOCKED` (green), or `BASE FREE` + the single action that would lock it (amber) |
| 3 | `BOX 0.33 m` — green inside the [0.28, 0.36] band, grey outside |
| 4 | mode flags, only when non-default: `PRECISION`, `B-PRIME OFF` |

- **Line 1 names one action, never three measurements**, chosen by a CAUSAL priority
  rather than by violation size: near → straddle → opposition. Palms that are not at the
  box make the other two meaningless — a wide stance a metre away reads as "hands apart"
  when the real problem is distance.

  | failing condition | line |
  |---|---|
  | palm-to-box, robot outside the grasp band | `STEP CLOSER` |
  | palm-to-box, robot already in the band | `REACH TO BOX` |
  | separation below `sep_min` | `HANDS APART` |
  | separation above `sep_max` | `HANDS TOGETHER` |
  | opposition above `opposed_dot` | `FACE PALMS IN` |

- **Line 2's lock action** uses the same ordering over the predicate's terms: standoff
  (`STEP CLOSER` / `STEP BACK`), lateral (`STEP LEFT` / `STEP RIGHT`), heading
  (`TURN LEFT` / `TURN RIGHT`), stillness (`STAND STILL`), then `LOCKING...` while the
  debounce runs. It appears only within 1.0 m of the box, so it is silent while walking in.
- **A tracking fault REPLACES line 1** with `TRACKING LOST` in red rather than adding a
  fifth line: grasp advice is meaningless when the arms are not following the operator.
- In MINIMAL the camera panel carries no text at all — no status line, no locomotion
  diagnostics. The skeleton overlay stays.

### FULL — key `o`, the diagnostic and reporting view

Everything the overlay had before: locomotion source, travelled, live velocity command,
lock state with every predicate term, standoff against the band, all four weld gate
conditions with numbers and pass/fail markers, the BLOCKING line, wrist deviation with
the WEDGE flag, heading, uncommanded-motion banner, locomotion diagnostics on the camera
panel, and the key hints.

### Key hints

No longer permanent. They show for the first **8 s** of a run and whenever FULL is on.
They also needed splitting into two lines: one line overflowed the 760 px panel at a
readable scale.

### Validation

- **Rendered offline and inspected**, since a window cannot be opened in this session:
  - MINIMAL in eight states: walking in far away, in-band but still moving, locked with
    the hands away, locked with hands too close, locked with palms turned the wrong way,
    READY, HELD with both flags, and tracking lost. 3–4 lines in every state.
  - FULL in two states (blocked and welded). Fits the panel with no overlap after the
    hint split.
- **Entry point still runs headless** with `synthetic_source`: `keyboard 0 --synthetic
  grasp --headless --start-standoff 0.32` gives the same lock 0.96 s / weld 9.49 s /
  release 12.72 s as before this change.
- **Scripted gates:** **12/12 and 40/40, byte-identical to the committed results.** Both JSON files were
rewritten this run (15:33 and 15:41) and `git diff` on them is empty. Expected: this
change touches drawing only.

### Not validated

The windowed path still has not been opened in this session, so the `o` toggle, like `u`,
`b` and `g`, is exercised only through the code path the headless run and the offline
renders cover. The first live session should check the `o` toggle early.

---

## 2026-09-15 — Teleop throughput: the sim ran at 37% of real time with a body detected. Now 128%.

**One change to the IK solver** — `mj_forward` inside the iteration loop replaced by
`mj_kinematics` + `mj_comPos` — takes the live loop from **37.4% to 128.2% of real time**
with a real body detected, and the arm trajectory is **bit-identical**. The hypothesis in
the brief was right about the call and wrong about the iteration count.

### 1. Sim-to-wall ratio, measured

`run_integrated_combined.py --profile` runs the real loop with the renderer and the
overlay, without the window, the key polling or the pacing, so the number is capacity and
not a measurement of the sleep. 30 s of simulated time each.

| source | before | after |
|---|---|---|
| **real ZED, body detected** | **37.4%** | **128.2%** |
| synthetic body (`--synthetic grasp`) | 124.6 / 128.9 / 128.9% | 178.4 / 178.5 / 176.4% |
| synthetic, NO body (`--synthetic none`) | — | 357% |

- The real-camera figure is the operator's complaint reproduced: at 37.4% the robot walks
  and turns at about a third of the speed the operator expects.
- **With no body the loop runs 357% of real time**, so the cost really is what happens on
  a frame with keypoints, exactly as reported.
- Ratios are noisy under machine load: one early post-fix run read 119.5% while something
  else was running. The before/after pairs above were run **interleaved**, three times
  each, and are stable to ~2%.
- The synthetic numbers are higher than the camera numbers because a synthetic frame is
  free to grab; the camera's own pipeline (NEURAL depth + HUMAN_BODY_ACCURATE) runs
  alongside and was separately measured at ~21 Hz with 77 dropped frames in 8 s.

### 2. Where the time actually goes

One `controller.step`, mean over 280 frames (`tools/teleop_throughput.py profile`):

| | before | after |
|---|---|---|
| **solve_arm_ik (both arms)** | **34.33 ms, 97.4%** | **16.91 ms, 94.0%** |
| retargeting | 0.14 ms, 0.4% | 0.11 ms, 0.6% |
| `robot.forward()` | 0.20 ms, 0.6% | 0.49 ms, 2.7% |
| smoothing, One-Euro, bookkeeping | 0.57 ms, 1.6% | 0.47 ms, 2.6% |
| **total** | **35.24 ms** | **17.99 ms** |

So it *is* the IK: retargeting and smoothing together are under 1% of the step. In the
whole loop, before the fix, `controller.step` was 43% of wall and the renderer 34%.

### 3. IK iterations — the brief's expectation was wrong, and this is why (b) is not adopted

    mean 30.00, median 30, p95 30, max 30, hit max_iter(30) on 100.0% of solves

**The solver never converges.** It warm-starts from the twin's current qpos as the brief
says, but `tol = 1e-3` is never reached, because 4 joints per arm (D2) cannot satisfy a
6-D elbow+wrist task: the residual plateaus above 1 mm and the loop always runs its full
30 iterations. Warm-starting buys nothing at all here.

### 4. Fix (a): `mj_kinematics` + `mj_comPos` in the solver loop

`mj_forward` also runs collision detection over the whole robot, builds and solves the
constraint system and evaluates actuation and the dynamics pipeline. The solver reads
body poses, site poses, and what `mj_jac` derives from `subtree_com` and `cdof`.

**Verified identical** before adopting (`tools/teleop_throughput.py verify`), over 25
random arm poses spanning the joint limits:

| quantity | max difference |
|---|---|
| `mj_jac` | **0.000e+00** |
| `xpos` | **0.000e+00** |
| `site_xpos` | **0.000e+00** |

**Speedup:** IK 34.33 → 16.91 ms per frame (2.03×); whole loop 37.4 → 128.2% of real
time with the camera.

### 5. (b) max_iter — measured, NOT adopted

Fix (a) already passes the 100% target, and lowering `max_iter` would change the SCRIPTED
demonstrator's solves as well (it shares `IKConfig`), which would break the byte-identical
gate requirement. Measured anyway, so the headroom is on record:

**Achieved error on the STEPPED model** (O25 harness, base locked, TR16a — the IK target
against the stepped wrist, each in its own pelvis frame):

| max_iter | p50 | p95 | max | ms per controller.step (twin) |
|---|---|---|---|---|
| 30 | 56.0 mm | 241.3 | 254.6 | 11.42 |
| 16 | 56.0 | 241.3 | 254.6 | 6.32 |
| 12 | 56.0 | 241.3 | 254.6 | 5.22 |
| 8 | 56.0 | 241.3 | 254.6 | 3.56 |
| 4 | 55.9 | 241.5 | 254.5 | 2.53 |

- **The 45 mm guard is already missed at max_iter = 30** (p50 56 mm): that error is
  retargeting loss and unreachable close-in targets (O19/O25), not iteration count.
  Iteration count moves it by ≤0.5 mm, so "the smallest max_iter that keeps palm error
  inside the guard" has no answer — nothing here is inside it.
- On the stepped grasp fixture, cutting 30 → 2 moved the achieved palm by **1.4 mm** and
  the weld still engaged (L 0.131 → 0.132, sep 0.253 unchanged).
- **What it does cost:** a transient lag on fast motion. Against the 30-iteration command,
  max_iter 20 differs by >0.05 rad on 3 ticks of 280 and max_iter 8 on 12 ticks, always on
  the right elbow during the fast reach, decaying to zero once the hand slows. Mean
  deviation stays ~1e-3 rad. It is a lag, not a different solution branch.

### 6. (c) Which `mj_forward` calls were kept, and why

| call | kept? | why |
|---|---|---|
| inside the solver loop, per iteration | **replaced** | nothing in the loop reads dynamics; identical Jacobians |
| the solver's trailing refresh | **replaced** with the same cheap pair | it exists so the twin matches the qpos just written — for the second arm's solve and for whoever reads `xpos`/`site_xpos` next; both are what `mj_kinematics` produces |
| `TeleopController._step_inner` → `robot.forward()` (full `mj_forward`, once per frame) | **kept** | 0.2–0.5 ms per frame against a 13–17 ms step, so there is nothing to win; and `G1Robot.forward` is shared with the preview entry points, where narrowing it would be an unmeasured change |

### 7. After the fix, what is next

At 128% with the camera the loop is no longer the limit. In the post-fix profile the
renderer is the largest remaining term (31–42% of wall, 4.9–7.0 ms per 25 Hz tick), then
`controller.step` at 27–29%. Two things now bound the operator's experience instead:

1. **the camera**, ~21 Hz with dropped frames (2026-09-15 recorder section), which sets
   how often the arms get a new pose;
2. **the renderer**, which is pure display and could be decimated further if needed.

### 8. Validation

- **Scripted gates:** **12/12 and 40/40, byte-identical.** Both result files were rewritten this run
  (16:52 and 16:59) and `git diff` on them is empty. This is the check that matters for
  the IK change: the scripted demonstrator solves its poses through the same
  `solve_arm_ik`, so a solver that moved at all would show up here.
- **Arm trajectory unchanged, two streams**, replayed through the real `TeleopController`
  (`tools/teleop_throughput.py replay --forward --save` / `--cmp`):

  | stream | ticks | max &#124;after − before&#124; |
  |---|---|---|
  | fabricated grasp-and-lift | 280 | **0.000e+00 rad** |
  | recorded ZED take (`smoketest_01`) | 160 | **0.000e+00 rad** |

  Bit-identical, not merely within tolerance. This is a speed fix.
- Headless synthetic grasp run: lock 0.96 s, weld 9.49 s, release 12.72 s — unchanged.
- Tests: spec 43/43, contact contract 14/14, keypoint recorder self-test PASS.

### 9. Tooling added

- `run_integrated_combined.py --profile` — the ratio and the per-section breakdown, the
  real loop rather than a replica. `--synthetic none` delivers body-less frames (the cheap
  path). `--ik-max-iter` and `--ik-mj-forward` are measurement knobs; `--ik-mj-forward`
  restores the old solver so before/after can be run back to back on the same machine.
- `tools/teleop_throughput.py` — `verify` (Jacobian identity), `profile`/`iters` (inside
  one `controller.step`, plus iteration statistics), `sweep` (command deviation vs
  max_iter), `stepped` (achieved error vs max_iter on the stepped model), `replay`
  (trajectory equivalence, `--save`/`--cmp`).
- `g1_teleop/ik.py` gained `COLLECT_STATS` / `ITERATIONS`, off by default.

### For the closeout (not fixed here)

**Demonstration timing is inconsistent while the sim runs off real time.** Below real time
the operator's motion is time-compressed in sim time, and the compression VARIES with
whether tracking is holding — 37% with a body, 100%+ without, before this fix. The
recorder must log the **sim-to-wall ratio per episode** (and ideally per tick) in its
metadata so the variation is visible in the dataset rather than silent. Above 100% the
pacing sleep absorbs the difference, so the ratio should sit at 1.0 and any episode that
drops below it is the one to look at.

---

## 2026-09-15 — PHASE 2 CLOSEOUT: the live session, the dataset design, and what moved into CLAUDE.md

Phase 2 is closed. This section records the material that existed only in chat sessions
and in this closeout brief, so CLAUDE.md can carry a pointer instead of the detail.

### 1. The live operator session — Objective 1 demonstrated end to end

**A live operator completed the full task through `run_integrated_combined.py` with the
ZED, under stepped physics: walked in, grasped, transported, placed.** That is Objective 1
demonstrated end to end, and it closes the "never executed" assumption that CLAUDE.md §13
had carried since 2026-09-08.

**Difficulties the operator reported, and what was done about each:**

| reported | response |
|---|---|
| piloting into the lock window is hard | the overlay was rewritten to give ACTIONS, not measurements (`STEP CLOSER`, `TURN LEFT`, `STAND STILL`), MINIMAL by default — see the overlay section above |
| walking and turning felt slow | `KeyboardCommand` runs well under the validated envelope (forward 0.35 m/s, turn 0.25 rad/s); the speeds are a deliberate choice for precise approach, not a limit of the policy |
| the sim ran below real time with tracking active | measured at 37.4% of real time and fixed — see the throughput section above; now 128.2% |

**THE GRASP WORKED WITHOUT THE BASE LOCK.** The operator completed the task free-based:
the box welded, lifted and stayed held, and the place succeeded.

- **Why O17 did not stop it.** The attractor standoff (0.47–0.59 m) was measured with the
  SCRIPTED station-keeper, whose corrective velocity is capped (`hold_max`). A human
  holding the forward key at full command pushes against the recession in a way the
  scripted controller never does.
- **Consequence, and it is a large one: D12 — the most consequential deviation in the
  project — may be needed only by the SCRIPTED demonstrator, not by collection or
  deployment.**
- **Not yet measured**, and both are needed before this can be acted on:
  1. the standoff spread at grasp without the lock, over seeds;
  2. whether a learned policy can fight the attractor the way a human does — a policy
     emitting velocity commands through the same channel may or may not sustain the push.
- **Why it is worth resolving before collection:** dropping D12 would remove a major
  limitation from every downstream result AND give Objective 4 natural standoff variation
  that the locked base cannot produce.

### 2. Dataset and evaluation design (decided in chat, recorded here)

**Collection.** 150 episodes. One `.npz` per episode. Seed streams **pre-partitioned before
collection** so that held-out leakage is provable by construction rather than audited
afterwards.

**Per-episode file contents:**

    states, actions, phase_labels, gait_phase, seed, box_spawn_xy, standoff_cmd,
    lateral_cmd, heldout, four per-phase success flags, placement_error, tilt,
    weld engage/release ticks, lock engage/release ticks, wrist_dev_rad,
    SIM-TO-WALL RATIO, reset_fingerprint, SPEC_VERSION, git commit, mujoco version

Total ~50 MB.

**Splits and normalization.** Train/val 80/20, stratified by binned spawn position.
Normalization statistics from the TRAINING SPLIT ONLY; masked dims pinned to mean 0 /
std 1 so a constant channel cannot be z-scored into unit-variance noise.

**Experiments.** Experiment 1: 100 FRESH in-region seeds. Experiment 2: 100 held-out-patch
seeds. Evaluation seeds are FIXED across all three policies. Data-scaling curve on NESTED
subsets 25 ⊂ 50 ⊂ 100 ⊂ 150.

**Collect 25 FIRST and train BC on them before collecting the rest.** If BC saturates at
25 episodes the task does not discriminate between the conditions, and the comparison
cannot answer RQ2/RQ3 no matter how much more data is collected. That is a cheap check
against an expensive mistake.

**Statistical limit, to state up front rather than discover in Chapter 4:** 100 evaluation
episodes give a standard error of ~5% on a rate near 50%, so two policies are separable at
roughly **15 percentage points**. Smaller differences are not measurable with this design.

### 3. The four schema-freeze decisions

Recorded because the reasoning, not just the outcome, is what a later session needs:

1. **Box position is stored in the WORLD frame**, with base-relative coordinates derived in
   the loader. One canonical frame in the file; derived views are the loader's business.
2. **Gait phase is EXCLUDED from the state vector** and logged as per-timestep metadata.
   It is a clock. Giving every policy a clock hands BC the temporal capability that
   ACT-LSTM is supposed to supply, which collapses the very gap RQ2/RQ3 exist to measure.
3. **The base lock is neither a state dim nor an action dim.** It is episode metadata plus
   an observable predicate (`g1_data/phases.py`), so nothing in the vectors encodes a
   mechanism the policy cannot cause.
4. **The episode cap comes from the measured distribution** (O10), not from the schedule.

### 4. What moved into CLAUDE.md in this closeout

§2 rewritten (Phase 2 closed, no blocker); §4 gains spec.py, the demonstrator settings, the
teleop parity work, the recorder and the IK performance and convergence facts; §7 gains
**D13–D18** and an amended **D2**; §8 gains the dated entries for the schema freeze, the
phase vocabulary, WALK_IN, the dataset design, the constant-dim mask, the lock predicate,
the O26 mitigation, the live session, the free-based grasp and the IK throughput fix; §9
gains **TR19–TR26**; §10 resolves O10, updates O25/O26/O19 and adds **O27–O30** plus the
Phase 1 exit-gate hole; §13 moves the entry-point and ZED-model assumptions to verified.

**The Phase 1 exit gate was incomplete**, and that belongs in the record rather than only
in the fix: it scored grasp, placement, resting, tilt and falls, and never scored
CLEARANCE. So the box scraped the pickup platform (−1.4 mm at the shipping `lift_h`) and
the hand penetrated it, in every episode, invisibly. "Phase 1 closed 12/12" is true on the
criteria as written, and the criteria had a hole. Under free lock timing the honest
reliability figure was **24/40 before the mitigation, 40/40 after**.

---

## 2026-09-16 — PHASE 3, first chunk: the recorder, the ledger, and what the replay test actually proves

**Built:** `g1_data/recorder.py` (episode recorder, observation only), `g1_data/ledger.py`
(crash-safe episode ledger), `tools/record_episodes.py` (operator controls + verdict),
`tools/replay_check.py` (the open-loop replay test with two negative controls and one
positive control).

**Not built, deliberately:** the phase labeller, success criteria beyond the rejection
checks, the dataset loader, normalization, chunking. Those are the next chunk and they
depend on this one being right.

**Headline.** The recorder logs the quantity that actually drove the robot — proven four
ways below. **Open-loop replay reproduces the MANIPULATION and does not reproduce the
WALK, and no recording rate can fix that.** That is a property of the action design (3 of
the 22 dims are a closed-loop station-keeper's corrective velocity), not a recorder fault,
and it changes what the Phase 3 exit criterion can honestly assert.

### 1. The recorder is observation only, measured

It attaches by wrapping `mujoco.mj_step` and reading `run_episode`'s frame locals — the
2026-09-10 audit's method — plus a wrapper on `reset_episode` that captures the post-reset
fingerprint. `scripted_demo.py` is not modified.

    tools/record_episodes.py --invariance 0
    compared 65 result fields; 0 differ
    OBSERVATION ONLY: CONFIRMED

Seed 0 run with and without the recorder agrees on **all 65** fields of the demonstrator's
result dict. That covers the `mj_kinematics` call inside `SpecLayout.build(sync=True)`,
which spec.py argues cannot perturb the simulation: it cannot, and now that is measured
rather than argued. The gates below are the second, independent proof.

### 2. What an episode file holds

706–846 ticks at 25 Hz, **~325 KB compressed** each; ~49 MB projected across 150 episodes.

| array | shape | note |
|---|---|---|
| `states` | (T, 47) f32 | via `SpecLayout.build`, never hand-assembled |
| `actions` | (T, 22) f32 | `data.ctrl` through the permutation; dims 19–21 zeroed while locked (D17) |
| `phase_labels` | (T,) i8 | the demonstrator's own `Phase`, not a labeller |
| `gait_phase` | (T, 2) f32 | metadata, never a policy input |
| `qpos`, `qvel` | (T, 45), (T, 43) f32 | **insurance** — see below |
| `step_index` | (T,) i64 | the demonstrator step each tick was taken at |

Metadata carries seed, spawn, held-out flag, standoff/lateral commands, the demonstrator's
outcome numbers, weld/lock engage+release ticks, wrist deviation, **sim-to-wall ratio**,
pre-grasp box disturbance, hand/platform penetration, `reset_fingerprint`, SPEC_VERSION,
git commit, mujoco version, and **`contact_contract`** read back from the compiled model.

**On raw `qpos`/`qvel`:** they are insurance, not a policy input. Almost anything one later
wishes were in the 47-D state is derivable from raw state plus an observation window
(velocity is a finite difference) — but LEG JOINT ANGLES are not, proposal 3.4 excludes
them, and once collected without them they are gone. Measured cost is ~110 KB of the
325 KB. That makes the state design the one dataset decision that cannot be regretted.

**One bug worth recording**, caught by the verdict printout on the first real episode: the
pre-grasp box-disturbance metric read **1411.6 mm** on a healthy episode. It was
accumulating whenever the weld was not engaged, which includes every tick AFTER the
release at the goal, where the box is legitimately 1.4 m from its spawn. Now bounded by
the first engage. A check that fires on a healthy episode is worse than no check.

### 3. The operator controls and the ledger

Each episode ends with the verdict printed, with numbers, before any decision:

    check                        result measurement
    weld fired                   PASS   engaged=True
    box not dropped              PASS   resting=True tilt=0.0 deg
    placement <= 0.10 m          PASS   0.0419 m
    no fall                      PASS   max pitch 7.3 deg
    wrist dev <= 0.8 rad         PASS   0.563 rad (left_wrist_pitch_joint)
    box undisturbed pre-grasp    PASS   0.1 mm
    hand/platform penetration    PASS   0.0 mm (0.0 = never touched, TR19)
    RECOMMEND: ACCEPT

Thresholds and their provenance: placement 0.10 m (Q4); wrist 0.8 rad on the pitch pair
post-REACH (TR23); pre-grasp disturbance 10 mm (measured demonstrator range 0.1–1.9 mm,
against 65–197 mm in teleop); hand/platform penetration −35 mm (measured demonstrator
range 0.0 to −28.3 mm — set at the edge of the MEASURED envelope, not at zero, because O26
is mitigated but not closed and a check that fails 40/40 healthy episodes tells the
operator nothing). Under D18 the demonstrator now reads 0.0 mm: no hand-platform contacts
exist at all.

**Ledger** (`recordings/episodes/ledger.jsonl`): append-only JSON Lines, flushed and
`fsync`ed per line, state rebuilt by replay. There is no in-place update for a crash to
corrupt, and a torn final line is skipped rather than poisoning the file. It records
session / issue / accept / discard / error with the seed, the checks, the held-out flag and
the path — so session three knows what sessions one and two consumed and the held-out leak
check is provable afterwards rather than asserted.

### 4. The open-loop replay test — the diagnosis

Five episodes, seeds 0–4. The test resets with the same seed, asserts the reset
fingerprint, restores the episode's own initial state (the base placement lives in
`run_episode`, not in `reset_episode`), then feeds the recorded actions back: 17 joint
targets through `spec.upper_ctrl_from_action`, 2 gripper dims to `GraspWeld.update`, 3
velocity dims to the locomotion policy. Nothing is driven from live state.

| episode | box while welded | arms while welded | weld tick Δ | lock tick Δ | base div, walk-in | base div, after release |
|---|---|---|---|---|---|---|
| seed 0 | 6.1 mm | 0.53 rad | 1 | 0 | 26 mm | **2.006 m** |
| seed 1 | 10.1 mm | 0.41 rad | 1 | 8 | 23 mm | 0.099 m |
| seed 2 | 4.9 mm | 0.51 rad | 1 | 1 | 24 mm | 0.409 m |
| seed 3 | 9.8 mm | 0.51 rad | 1 | 1 | 25 mm | **1.612 m** |
| seed 4 | 14.5 mm | 0.54 rad | 1 | 2 | 21 mm | 0.595 m |

- **Reset fingerprint: 5/5 match.** So the divergence is not (b), an unreset episode.
- **Manipulation reproduced: 5/5.** The weld fires within ONE tick of the recorded tick
  every time, and the box tracks within 14.5 mm through the entire welded window.
- **Whole task reproduced: 1/5** (seed 1, placement 0.099 m). The other four miss the
  placement by 0.4–2.0 m, all of it accumulated after the base lock releases and the robot
  walks 1.5 m to the goal.

**Which of (a), (b), (c) is it? None of them.** Evidence for each, in the order the brief
asks:

1. **(a) wrong quantity — ruled out by alignment.** Every recorded velocity command was
   compared against the demonstrator's own `act` at that exact step: **0 of 706 recorded
   ticks disagree**. The recorder logs the right quantity at the right instant.
2. **(b) something not reset — ruled out by the fingerprint**, 5/5.
3. **(c) routing/permutation — ruled out by a POSITIVE control.** Routing `action[0:17]`
   straight into `ctrl[upper_ctrl]` (the exact mistake spec.py exists to prevent) is
   unmistakably different: arm divergence **1.73 rad** instead of 0.53, the weld **never
   fires**, the base lock **never fires**, and the walk-in diverges 0.54 m immediately
   instead of 26 mm. The test can see a routing error; the current routing is not one.
4. **The real cause: an open-loop walk is not reproducible, at any recording rate.**
   Feeding the demonstrator's OWN 50 Hz velocity series instead of the 25 Hz recording
   makes it **worse, not better** (base divergence 3.435 m vs 2.006 m). The 25 Hz sampling
   does lose something real — the missed intermediate command averages 2–4% of command
   magnitude, with maxima of 0.77 rad/s at correction moments — but supplying it does not
   help, which is the point. Base divergence after release grows **exponentially**:
   15 mm at 1 s, 47 mm at 2.4 s, 692 mm at 4.8 s, 2006 mm at the end — a doubling time of
   roughly 0.7 s. That is the signature of an unstable open-loop process, not of a constant
   offset or a wrong signal.

**Why this is structural, not a bug.** Three of the 22 action dims are the output of a
closed-loop station-keeper that reads base position every control tick and corrects. Replay
by construction has no feedback path, so a corrective command recorded at one state is
applied at a slightly different state, and a bipedal walk amplifies the difference. The
manipulation window is reproducible precisely because the base is welded there (D12): the
locomotion channel is inert, D17 zeroes it, and the 17 joint targets are an open-loop
command in the demonstrator too.

**What the Phase 3 exit criterion can therefore assert**, and what it cannot:

- CAN: the reset is deterministic; the recorded 17 joint targets + gripper command
  reproduce the grasp to within a tick and the box to within 15 mm; the routing and the
  permutation are right; the negative controls fail.
- CANNOT: that replaying an episode open loop walks the robot back to the goal. PLAN.md
  Phase 3's criterion ("replayed open-loop, reproducing the original trajectory within a
  stated tolerance") is met for the manipulation channel and is **not achievable** for the
  locomotion channel by any recorder.

**This is not a blocker for training, and it is a warning about metrics.** A trained policy
closes the loop — it sees state at 25 Hz and re-issues velocity commands — so it is not
replaying open loop. But it means an open-loop metric (action MSE, or "replay divergence")
will look far better than task success for the walking segments, and Chapter 4 must not
quote one as evidence for the other.

### 5. The negative controls, and what the second one exposed

**Control A — box displaced 235–250 mm, beyond the 0.16 m weld gate:** task fails 5/5, weld
refused 4/5. **Control B — actions replayed against another seed's spawn** (the brief's
literal wording): task fails 5/5, weld still fired 4/5.

The weld firing is not the test failing, and the trace says why. Seed 4 under control A:
the arm **shoved the displaced box 185 mm** before the gate conditions were met (L 0.123 m,
R 0.109 m, opposition exactly −0.50, separation 0.201 m), and the episode then wrecked —
the box ended **3.36 m** from where it was placed. Under control B the shifts are often
small (36 and 39 mm on two pairs) and the gate tolerance is 160 mm, so a weld is the
CORRECT outcome there.

So "the weld must not fire" is an unsound criterion for a free body the arm can reach; the
brief's own criterion — the task must fail — is the sound one, and both controls satisfy it
5/5. Recorded because the same trap will appear in the success detector next chunk: the
weld gate does not imply the right box.

**One more thing control A shows:** the demonstrator's recorded hand trajectory tolerates a
±40 mm spawn shift and still grasps. That is the 0.16 m gate doing its job, and it is worth
knowing before Objective 4 reads spatial generalization off a 60 mm held-out patch offset.

### 6. Validation

- **Scripted gates:** **12/12 and 40/40, byte-identical.** Both result files were rewritten this run (05:57
  and 06:03) and `git diff` on them is empty. The recorder does not touch
  `scripted_demo.py`, and this is the independent check that recording changed nothing.
- Spec tests 43/43; contact-contract tests 14/14.
- Replay on **5 episodes across 5 seeds**, both negative controls, plus the positive
  control.
- `--invariance`: 65/65 result fields identical with and without the recorder.

### For the closeout

- PLAN.md Phase 3's exit criterion needs the qualification in section 4 above: open-loop
  replay validates the manipulation channel; the locomotion channel cannot be validated
  that way.
- The next chunk (phase labeller, success criteria, loader) should read the four per-phase
  flags off the quantities already in each file — nothing further needs recording.
- `docs/measurements` is not where episodes go: `recordings/episodes/` is gitignored
  (`*.npz`), so the dataset needs the off-machine backup PLAN.md Phase 6 already calls for.

## 2026-09-16 — PHASE 3, second chunk: success detection, the offline phase labeller, the dataset, and normalization

Four pieces, no model code. The two things worth reading if nothing else: the proposal's grasp
criterion and its lift criterion are **both** satisfiable by an episode that failed, and each
needed a deviation row (**D19**, **D20**). Both were found by deliberately breaking a healthy
episode, not by reading the text.

### 1. Success detection — and two unsound criteria in §3.8.2

`g1_data/success.py`. The four criteria are pure functions of a RECORDED episode plus its
metadata: nothing is computed live, so a recording can be re-scored after the thresholds change
without re-running physics. That matters because the thresholds did change twice below.

**D19 — the grasp criterion needs the box to still be where it spawned.**
§3.8.2 reads "grippers closed AND box above the platform". The replay negative control from the
first chunk satisfies both while failing: the arm shoved the box **185 mm** into its own palms,
at which point the weld gate's proximity/opposition/separation conditions were all genuinely met
and the box was genuinely above the platform. Nothing in the criterion distinguishes "reached
the box" from "pushed the box until it was reachable", and *bulldoze until the gate fires* is
exactly the degenerate strategy a policy will find. Added: at the engage tick the box must be
within **50 mm** of `box_spawn_xy`.

The threshold is measured, not chosen. Over the 40 healthy scripted episodes the box moves
**0.0–1.9 mm** from spawn before engage (mean 0.3). 50 mm is **26x the worst healthy episode**
and **3.7x below** the bulldoze it has to reject — separation of that size is why it can be a
fault detector rather than a tuned threshold.

**D20 — the lift criterion is vacuous read as the box centre.**
The injected `never_lifted` fault — hold the box on the platform for the whole episode — was
**MISSED** on the first run. The box is 0.18 m, so at rest its CENTRE already sits 0.09 m above
the platform top, and "box centre >= 0.05 m above the platform" is true before the robot touches
it. Scored on the box **BOTTOM** instead, which is what "lifted" means. Caught after the change.

This one is worth stating plainly in the writeup: the criterion as written cannot fail, so any
lift success rate computed from the proposal's text would have been 100% by construction.

**Thresholds and where each came from.** Two were wrong the first time and both failures were
the same mistake — inventing a number instead of measuring the healthy population:

| threshold | value | provenance |
|---|---|---|
| `lift_above_platform` | 0.05 m | §3.8.2, but of the box BOTTOM (D20) |
| `place_radius` | 0.10 m | `d_place`, Q4 — unchanged from the proposal |
| `upright_deg` | 15 deg | measured max 10.9 deg |
| `resting_tol` | 0.03 m | 1.6x the measured max (18.3 mm) |
| `settled_speed` | 0.25 m/s | 4x the measured max (0.060 m/s) |
| `grasp_spawn_max` | 0.05 m | D19, 26x the measured max (1.9 mm) |

`settled_speed` was first set to 0.05 m/s out of nowhere and disagreed with the demonstrator on
seed 24. The measured healthy population peaks at 0.0603 m/s, i.e. **the invented threshold sat
inside the healthy distribution**. Related: the demonstrator's own "resting" test is a CONTACT
test (`scripted_demo.py:1243`) and is **not derivable from a recording at all** — the recorded
approximation is a displacement-plus-speed test, which is why it needs a tolerance and the
demonstrator does not.

**Validation.** 40/40 agreement with the demonstrator's independently computed `outcome.ok`
(different code, computed live, from the stepped model). All six injected faults caught:
`no_weld`, `box_dropped`, `placement_out`, `tipped`, `bulldozed`, `never_lifted` — the last two
being the ones that found D19 and D20.

### 2. The phase labeller is OFFLINE, and the reason is in its docstring

`g1_data/phase_label.py`. Derives `spec.Phase` from recorded state only — weld bit, box height,
box-to-base distance, lock ticks. **No live phase classifier is needed anywhere**, which is what
lets teleop record episodes without an operator-side phase machine (the 2026-09-08 decision).
It uses `spec.Phase` and `spec.SCORED_OF`; there is no second vocabulary.

**What actually made it work was reusing `LockPredicate`, not adding thresholds.** It went
50.9% -> 53.0% -> 55.1% per-tick through three rounds of threshold tuning, and the LOWER boundary
was still 2575 ticks wrong. Running the project's own `LockPredicate` over the recorded states
offline — recovering BOTH lock instants, where the recorder stores only the first — took it to
**64.6%** and the LOWER offset to −1 tick. The lesson is the same one as `settled_speed`: the
information was already in the project, in a validated component, and inventing a threshold was
the slower path.

**Confusion matrix, 40 episodes, 30256 ticks** (rows truth, columns derived):

```
             SETTLE   REACH  REPOSI  APPROA   GRASP    LIFT    MOVE   LOWER  RELEAS  VERIFY
  SETTLE       3478      40       0       0       0       0       0       0       0       0
  REACH           0    3000       0       0       0       0       0       0       0       0
  REPOSI          0    6000       0       0       0       0       0       0       0       0
  APPROA          0    2000       0       0       0       0       0       0       0       0
  GRASP           0     800       0       0     800       0       0       0       0       0
  LIFT            0       0       0       0    1120     521     359       0       0       0
  MOVE            0       0       0       0       0       0    5618      40       0       0
  LOWER           0       0       0       0       0       0       0    2000       0       0
  RELEAS          0       0       0       0       0       0       0       0    1642     358
  VERIFY          0       0       0       0       0       0       0       0       0    2480
```

- all 10 phases: **19539/30256 = 64.6%**
- the 5 SCORED buckets: **28697/30256 = 94.8%**

**The gap is one block and it is not a defect.** REACH / REPOSITION / APPROACH are three
schedule stages of the same motion — the arm descending beside the box — and they are **not
separable from state**, because the state does not record which schedule segment produced it.
All three map to `ScoredPhase.GRASP`, so the taxonomy the labels exist for is unaffected. That
is the whole 8000-tick difference between 64.6% and 94.8%.

**Per-boundary offsets, derived minus truth, in ticks at 25 Hz:**

| boundary | offset | spread |
|---|---|---|
| SETTLE | +0 | exact, 40/40 |
| REACH | −1 | exact, 40/40 |
| GRASP | +20 | exact, 40/40 |
| LIFT | +28 | exact, 40/40 |
| MOVE | −9 | −11..−7 |
| LOWER | −1 | exact, 40/40 |
| RELEASE | +0 | exact, 40/40 |
| VERIFY | −9 | −11..−7 |

Six of the eight are **identical on all 40 seeds**; the other two vary by 4 ticks (160 ms) and
are consistently EARLY, never sometimes-early-sometimes-late. This is the "consistently late is
fine, erratic is not" test passing: every boundary has a fixed sign and a spread under 0.2 s.
GRASP +20 and LIFT +28 are the largest and both are *late* by construction — the weld bit and
the box height are consequences of the motion, and they change after the demonstrator's schedule
says the phase did.

**On a teleop recording, with no ground truth** (`recordings/teleop_ep.npz`, the headless
synthetic fixture, 550 ticks):

```
SETTLE -> REACH -> GRASP -> LIFT -> MOVE
```

Monotone, **0 hysteresis corrections**, 4 transitions, no phase entered twice, no oscillation.
The trailing phases collapse to tick 550 because the fixture grasps and lifts but never
transports or places — the labeller reporting three empty phases at the end is correct, not a
failure to detect them. This is the plausibility check the brief asked for and it passes.

### 3. The dataset, and a leak the layout caught in its own data

Layout: `data/raw/train/`, `data/raw/heldout/` (**must stay empty** — that emptiness IS the
leak check), `data/synthetic/`, `data/eval/`, `data/processed/`. Scripted episodes are staged to
`data/synthetic/` and never mixed with real data.

**The loader RAISES, it does not warn**, on three things: mixed `SPEC_VERSION`, mixed
`contact_contract` (D18 — half a dataset in different physics), and a held-out spawn among the
training episodes. A warning would be read on the day it was written and never again.

**THE FINDING: the seed stream was not partitioned, and 5 of 45 episodes leaked.** Running
`split` on the staged scripted episodes raised:

```
DatasetError: 5 accepted training episode(s) spawned inside the HELD-OUT patch:
seeds [15, 18, 23, 37, 40]
```

This is the check working, on real recorded data, and it is not a small effect: **11% of the
recorded set (5/45)**, consistent with the held-out patch's measured **14.25%** area fraction.
Those episodes came from a contiguous seed stream 0–44 because nothing partitioned it — the
recorder issued seeds in order and neither it nor the demonstrator has any notion of the
held-out patch. **A 150-episode collection run would have leaked ~21 episodes into Objective 4,
and the only thing that would have caught it is an audit run after the collection cost was
already paid.**

Fixed in the direction CLAUDE.md §8 already specified ("seed streams pre-partitioned before
collection so leakage is provable, not audited") — the specification existed, the code did not:

- `dataset.partition_seeds()` walks the seed space, classifies each seed by `in_heldout`, and
  writes three disjoint streams to `data/eval/`: **train** (in-region, for collection),
  **exp1** (in-region and disjoint from train — D16: Exp 1 uses FRESH seeds, not collection
  spawns replayed back), **exp2** (the held-out patch). Disjointness is by construction, and
  tested.
- `stage` now **quarantines** held-out spawns at the door rather than copying them in. The
  audit in `split` stays as a second line, but it is no longer the only line.

The 5 leaked episodes were quarantined; 40 of 45 staged.

**The 80/20 split was really 90/10.** Stratification bins the spawn region into a 3x3 grid and
splits within bins — correct, because the stratifying variable is continuous and 2-D, and a
random split of 150 episodes leaves the 30 validation episodes clustered in some corner by
chance. But taking "every 5th episode within a bin" silently drops the fraction: a bin holding 3
or 4 episodes never reaches index 4 and contributes **no validation episodes at all**. The split
came out **36/4 = 90/10 wearing an 80/20 label**, and nothing reported it. Replaced with a
per-bin quota that carries its remainder to the next bin: now exactly **32/8 = 80/20**, and
**30/150 at the planned collection size**, tested at both.

Two bins get no validation episode at 40 episodes, because 8 cannot cover 9 bins. That is
arithmetic, not a bug, so it is REPORTED (`bins_without_val`) rather than hidden; at 150
episodes every bin draws ~3.

**Coverage** against the ledger: 45 accepted, 40 on disk, 5 missing-from-disk (the quarantined
held-out seeds, accounted for), 0 not-in-ledger, 0 rejected, spawn x [1.4405, 1.5547]
y [−0.2099, 0.2047], held-out leak **NONE**.

### 4. Normalization — training split only, and the binary dims are fine

`NormStats` fitted on the **32 training episodes only** (24242 ticks). Validation, evaluation
and synthetic data never enter the statistics; synthetic needs an explicit `--allow-synthetic`
flag, and which source was used is written INTO the stats file so it cannot be forgotten.
Saved to `data/processed/norm_stats_v1.npz`, versioned with `SPEC_VERSION`.

- **Masked action dims (6, 13, 14, 15, 16, 18): mean 0 / std 1 exactly.** Verified on reload.
- **Round trip** normalize -> denormalize after saving and reloading: max |error| **2.22e-16**
  on both state and action, i.e. one float64 ulp.
- **Nothing hit `STD_FLOOR`** (1e-6). The smallest unmasked state std is dim 43
  `q_right_wrist_yaw` at 2.03e-3; the smallest action std is dim 5 `a_left_wrist_pitch` at
  6.42e-2.

**The binary weld-bit dims (state 28 and 29, D14): normalized like any other dim, deliberately.**
Checked rather than assumed, because z-scoring a binary dim can be absurd. Here it is not:
mean **0.347**, std **0.476** — a Bernoulli with p ~ 0.35, which is a real 2.1 sigma separation,
and z-scoring maps it to exactly two values, **−0.73 released** and **+1.37 welded**. An affine
map of a two-valued variable is still two-valued: no information is created or destroyed, and
the weld bit stays exactly as recoverable after normalization as before.

The case where this WOULD be absurd is the one D14 already documents — `pad_qpos` has std 9e-4
of pure noise, and z-scoring it would amplify noise to unit variance and hand the policy a
feature made of nothing. The distinguishing question is not "is the dim binary" but "is the
variance signal". For dims 28/29 it is the grasp itself.

### 5. Validation

- **Scripted gates: 12/12 and 40/40, BYTE-IDENTICAL.** Both result files rewritten this run;
  `git diff docs/measurements/` is empty. Nothing in this chunk touches `scripted_demo.py`,
  `spec.py` or the demonstrator's behaviour.
- Spec tests **43/43**; contact-contract tests **14/14**; new dataset tests **13/13**.
- Success detection: **40/40** agreement with the demonstrator, **6/6** injected faults caught.
- Phase labeller: confusion matrix over 40 episodes above; teleop sequence monotone.
- Loader refusals proved on **deliberately corrupted real .npz files on disk**, not just
  hand-built metadata dicts — mixed `SPEC_VERSION` and mixed `contact_contract` both raise
  through `scan()`.
- Normalization fitted, saved, reloaded, round-tripped.

### For the closeout — do not write it here

1. **Two new deviation rows.** **D19**: the §3.8.2 grasp criterion admits a bulldoze; add the
   box-near-spawn condition, 50 mm, 26x the healthy maximum. **D20**: the §3.8.2 lift criterion
   is vacuous read as the box centre (a 0.18 m box at rest is already 0.09 m above the platform);
   score the box BOTTOM. Both affect chapter 3.8 and both belong in the results as *criteria
   that could not fail as written*.
2. **A §9 entry is arguable** for "inventing a threshold instead of measuring the healthy
   population" — it cost two wrong numbers in one session (`settled_speed` 0.05, and three
   rounds of labeller tuning) and both were fixed by measuring.
3. **The leak is a §8 decision entry**, not just a bug: collection cannot start from an
   unpartitioned seed stream, and `data/eval/{train,exp1,exp2}_seeds.json` now exist so it does
   not have to.
4. **O-issue candidate:** the per-tick phase agreement of 64.6% will be quoted somewhere, and
   the honest figure for the taxonomy is **94.8%** — the difference is entirely REACH /
   REPOSITION / APPROACH, which no state-based labeller can separate. State which one is being
   quoted and why.

---

## 2026-09-21 — The overfit-10 gate criterion was REVISED, after seeing a result

**Revising a gate after seeing the result it produced is legitimate only when the
revision is visible.** This entry exists so it is. What follows is the original
criterion, the measurement that motivated the change, the new criterion, and the
reasoning — in that order, so a reader can disagree with the reasoning without
having to reconstruct the sequence.

### The original criterion

Phase 4 Stage 2 (`tools/train_bc.py overfit10`) gated on: *train BC on exactly 10
episodes, with no validation, no regularization and no augmentation; the model
must drive training loss to near zero.* "Near zero" was operationalised in the
session as **< 10% of the copy baseline**.

The rationale was standard: a model that cannot memorise ten episodes has a bug
in the loss, the masking, the shape contract or the optimizer wiring, and every
later number is meaningless. That rationale is still correct.

### What was measured (Stage 2, 2026-09-20)

BC, 2x512 MLP, 298,518 parameters, 300 epochs, 103.7 s on the RTX 3050:

| quantity | value |
|---|---|
| final train loss | **0.009200** |
| ZERO baseline (predict the normalized mean) | 0.694891 |
| COPY baseline (predict the previous tick's action) | 0.016331 |
| as a fraction of ZERO | 0.0132 (75.6x better) |
| as a fraction of COPY | **0.558** (1.8x better) |

Under the original criterion this **fails**: 0.558 is not < 0.10. Two diagnostics
were run before concluding anything, and both said the failure was in the
criterion.

**1. The state does not determine the action at this data density.** For every
one of the 7,628 samples, the nearest *other* sample in 47-D state space was
found and the two actions compared over the 16 trainable dims:

    median state distance to the nearest other sample   0.200
    mean |action - action(nearest neighbour)|            0.012764

The trained model's own error, **0.009200, is BELOW that 0.012764**. The model
already predicts better than "copy the action of the closest observation you have
ever seen". Asking it for "near zero" was asking for something the data does not
contain: two ticks 40 ms apart have nearly identical states and genuinely
different commanded actions, and no deterministic function of the state produces
both.

**2. Half the residual is one identifiable, structural thing.** Per-dim error:

| group | dims | error |
|---|---|---|
| all trainable | 16 | 0.009512 |
| arm + gripper | 13 | **0.006026** |
| velocity (19-21) | 3 | **0.024618** |

The three velocity dims are 18.8% of the trainable dims and **48.5% of the loss**.
Splitting those ticks by base-lock state:

| | ticks | velocity err | arm err |
|---|---|---|---|
| lock ENGAGED | 3,480 | **0.003678** | 0.004867 |
| lock DISENGAGED | 4,148 | **0.042185** | 0.006997 |

11.5x worse unlocked. While locked, D17 pins the velocity target to exactly
`[0,0,0]` and the model reproduces it. Unlocked, the target averages
`[0.183, 0.221, 0.168]` and is a `KeyboardCommand` / station-keeper output that
is not a smooth function of the 47-D state. **The lock state is deliberately not
in the state vector** (schema freeze, 2026-09-11: "neither a state nor an action
dim — episode metadata plus an observable predicate"), so the model cannot see
the variable that determines its single largest error term. That is partial
observability, not under-capacity.

**Also worth stating: the COPY baseline uses information the model does not have.**
BC at W_o=1 sees the 47-D state and no action history, while COPY is handed
`action[t-1]`. Requiring BC to beat it by 10x was requiring it to beat something
closer to an oracle than to a peer. That was not noticed when the threshold was
written.

### The new criterion

> **A stage passes when its training error on 10 episodes falls below the
> neighbour-ambiguity reference computed for that stage's own loader
> configuration.**

Implemented as `g1_model/ambiguity.py`: `neighbour_ambiguity()` and `gate()`,
called by `tools/train_bc.py`, tested in `g1_model/test_ambiguity.py` (17 tests).
Both numbers and the ratio are printed at every gate and written to
`<run>/gate.json` — a verdict without them cannot be checked.

The reference is computed **per loader configuration**, in the flattened
observation window exactly as `ChunkDataset.__getitem__` assembles it, so it
moves with `obs_window` and with `chunk_size`. A single global number would
silently favour whichever stage happened to match it.

**Re-run under it (2026-09-21), both gates pass:**

| stage | W_o | K | train error | reference | ratio |
|---|---|---|---|---|---|
| BC | 1 | 1 | 0.009200 | 0.012764 | **0.721** |
| chunked BC | 1 | 100 | 0.042763 | 0.044657 | **0.958** |

The references differ by 3.5x between the two stages, which is the point: at
K=100 the model predicts 4.0 s of future action from one observation, and the
neighbour comparison is over that whole horizon. A fixed threshold would have
called one of these two a failure for reasons having nothing to do with the model.

### Why this is the right criterion, and what it does not claim

It is an **empirical proxy for irreducible error, not a bound.** Nothing here
proves a model cannot do better. Two neighbours differing by *d* do not force an
error of *d*: the best deterministic L1 predictor sits at the conditional median,
costing about *d*/2 for a coincident pair, so the reference is **lenient by
roughly a factor of two**. A model beating it has reached the resolution the data
supports at this density — not any theoretical floor.

Consequences that must be stated wherever the number is cited (they are in the
module docstring and in `AmbiguityResult.cite()`, which is what should be quoted
rather than `.mean`):

- **It falls as episodes are added.** Measured, K=1, W_o=1: 3 episodes 0.002779,
  10 episodes 0.002386, 32 episodes 0.002077 (identity normalization). So a model
  that passes against a 10-episode reference may fail against a 150-episode one
  **without having changed**. It is not comparable across dataset sizes.
- **It inherits the data's character.** Computed on scripted episodes it describes
  the scripted demonstrator. Every Phase 4 gate must be re-run on piloted data
  before any result resting on it is reported.
- **Across `obs_window` it is confounded by dimensionality** — see the next entry.

---

## 2026-09-21 — The W_o selection instrument, and the confound in it

Stage 4 needs W_o fixed before either ACT variant trains, identical across both,
and justified in Chapter 3 by something other than a sweep — a sweep picks the
window that suits the model, which is the confound it would need to avoid. So the
instrument is a **measurement of the data**: neighbour ambiguity as a function of
`obs_window`, with no model involved (`ambiguity_curve`, `train_bc.py wo-curve`).

**Measured on 32 SCRIPTED episodes, K=1, real normalization stats:**

| W_o | ambiguity | vs W=1 | nn-dist p50 | dims |
|---|---|---|---|---|
| 1 | 0.009608 | 1.000x | 0.1523 | 47 |
| 2 | 0.009982 | 1.039x | 0.2226 | 94 |
| 4 | 0.010426 | 1.085x | 0.3444 | 188 |
| 8 | 0.011049 | 1.150x | 0.5226 | 376 |
| 16 | 0.011128 | 1.158x | 0.8211 | 752 |
| 32 | 0.011850 | 1.233x | 1.3339 | 1504 |

**The curve RISES monotonically. It has no falling region, so there is no knee to
read.** A longer window cannot destroy information, so the rise is the estimator,
not the data: growing W_o multiplies the search space by W_o while the sample
count stays fixed, neighbours get relatively farther — median distance grows 8.8x
across a 32x larger space — and their actions differ more for reasons unrelated
to what the window explains. Recorded as **limit 6** in `g1_model/ambiguity.py`
and pinned by `test_the_obs_window_dimensionality_confound_is_real_and_visible`.

How to read such a curve:

- a **falling** region is informative — the window explains more than the added
  sparsity costs;
- a **rising** region means only that the dataset cannot populate a space that
  big. Still useful: it says *data density*, not architecture, caps the usable
  W_o. It is **not** evidence that a longer window is worse;
- the **minimum is not automatically the right W_o**.

`neighbour_distance` is reported at every point so the confound is visible rather
than inferred. A density-matched estimator — compare at equal neighbour distance
rather than equal sample count — is the fix, and is **not built**.

**The curve above cannot choose W_o**, for two independent reasons: the scripted
action distribution is not the piloted one, and at 32 episodes there is no falling
region to read. The instrument is built and proven; the measurement that matters
is one command (`tools/train_bc.py wo-curve`) once piloted data exists.

---

## 2026-09-21 — Chunked BC is the same class as BC

Stage 2's `BCPolicy` refused `chunk_size > 1`, so chunked BC would have had to be
a second class. Lifted in Stage 3. If chunked BC were a separate class, the
measured effect of chunking would include every incidental difference between two
implementations — initialization, head shape, anything — and the isolation the
stage exists to provide would be gone. The only difference between the two
conditions is now the number of actions predicted from one observation.

`K_PROVISIONAL = 100` (4.0 s at 25 Hz) is the value ACT uses in the original
paper and is the **only** reason it was picked. It was not swept. Episodes here
run 694-846 ticks, so it covers about an eighth of one. The right K depends on
how long a piloted operator's intent stays coherent, which cannot be measured on a
scripted demonstrator that never changes its mind. **Settle it on piloted data.**

**No temporal ensembling** (`models.first_action`): that is an ACT mechanism and
belongs to Stage 4. Folding it in here would mean Stage 3 measured chunking *and*
ensembling with no way to separate them. A chunked policy commits to its first
prediction and re-plans on the next tick.

---

## 2026-09-21 — The ACT reference: what was pinned, and what reading it found

Phase 4 Stage 4 session 1 wrote no model code. It established what ACT actually is, from
the source, so that sessions 2 and 3 implement against a citable artefact rather than
against recollection. Full detail in `docs/ACT_CORRESPONDENCE.md` and
`docs/ACT_AUDIT.md`; this entry records the pin and the findings that change decisions.

### The pin

| | |
|---|---|
| repository | `https://github.com/tonyzhaozh/act` — resolved, not moved or renamed |
| commit | **`742c753c0d4a5d87076c8f69e5628c79a8cc5488`** |
| commit date | 2024-01-28 12:18:07 -0800, branch `main` |
| clone | `reference/act/` — **gitignored**, never vendored into the tracked tree |
| paper | Zhao, Kumar, Levine, Finn, *Learning Fine-Grained Bimanual Manipulation with Low-Cost Hardware* |
| arXiv | **2304.13705v1**, 23 Apr 2023 — v1 is the only version |

That hash is what makes every `file:line` citation in the two documents checkable. Against
any other commit the line numbers are meaningless.

### Five findings that change what we build

**1. The reference's state-only path is unreachable dead code, and it drops the CVAE.**
`DETRVAE.forward` has a `backbones is None` branch (`detr_vae.py:132-136`) that looks like
exactly what a state-only adaptation wants. It is never reached: `build()` constructs
backbones unconditionally (`:235-237`). Worse, that branch calls
`self.transformer(transformer_input, None, self.query_embed.weight, self.pos.weight)` with
four arguments and **never passes `latent_input`** — the vision path passes seven
(`:131`). Copying the obvious-looking branch would produce an "ACT" with no CVAE
conditioning at all, i.e. chunked BC with an unused encoder, and RQ2/RQ3 would compare a
model against itself. **Take the vision branch's wiring and delete only the image tokens.**

**2. ACT builds seven decoder layers and trains one. MEASURED.**
`dec_layers = 7` (`imitate_episodes.py:55`, paper Table III), but `detr_vae.py:131` reads
`hs[0]`, and `transformer.py:76` returns `(num_dec_layers, bs, num_queries, d)` — so `[0]`
is the **first** layer, not the last. Measured on this commit with a 7-layer decoder:
output shape `(7, 3, 11, 16)`; backward through `hs[0]` gives decoder layer 1 a gradient
of L1 `7.41e-05` and layers 2–7 **exactly `0.0`**. This was reasoned about first and got
the wrong answer; the gradient measurement settled it (TR18's rule, again).
Consequence: we cannot both replicate faithfully and report "7 decoder layers" honestly.
Options and a recommendation are in `ACT_CORRESPONDENCE.md` §5 — recommendation is to
build **one** layer and state in Chapter 3 that the reference builds seven and trains one.

**3. The paper contradicts itself on the loss.** Algorithm 1 line 9 says
`Lreconst = MSE(...)`; §IV-C prose says "We use L1 loss for reconstruction instead of the
more common L2 loss"; the code uses `F.l1_loss` (`policy.py:30`). Two sources against one:
**L1**. Our Stage 2 loss is already L1, chosen for the same reason, so the ladder is
consistent by luck rather than by checking — now checked.

**4. The reference's loss reduction is not K-invariant, and its normalisation leaks.**
`l1 = (all_l1 * ~is_pad.unsqueeze(-1)).mean()` (`policy.py:31`) zeroes padded entries and
then divides by the **full** element count, so the loss depends on how much padding a
batch happened to contain. Our `masked_l1` divides by contributing elements, which is
required for the K=1 vs K=100 comparison to mean anything. Separately,
`get_norm_stats` is computed over **all** episodes before the split (`utils.py:115-120`),
leaking validation statistics into the normaliser — the exact failure our Stage 1 A3 work
exists to prevent. **We are deliberately stricter than the reference in both places, and
both divergences must be disclosed rather than presented as fidelity.**

**5. Paper/code disagreements, collected.** Decoder queries are `nn.Embedding` — learned
(`detr_vae.py:54`) — while paper §IV-C calls them "a fixed position embedding". One
ResNet18 is shared across all cameras (`:121`, `:235-237`) while Figure 11 shows one per
camera. The temporal-ensembling weight has **no numeric value in the paper**; the only
number is `k = 0.01` (`imitate_episodes.py:255`), and that variable name collides with the
paper's `k` for chunk size. Any `m` attributed to the paper would be fabricated.

### Chunk size and horizon (D4)

`DT = 0.02` (`constants.py:36`) → ACT runs at **50 Hz**; chunk size 100 → **2.0 s**. We run
at 25 Hz (D4), so K=100 is **4.0 s** and K=50 is 2.0 s. Their episodes are 400 steps = 8 s
and a chunk is 25% of one; ours are 694–846 ticks = 27.8–33.8 s and K=100 is ~13%.
**Matching the number** keeps the methods table identical to the paper; **matching the
horizon** (K=50) predicts the same physical span, which is the quantity that plausibly
transfers, since a chunk is a unit of intent and intent has a duration in seconds. Stage 3
used K=100 provisionally because it is ACT's published number and for no other reason.
Neither can be settled on scripted data.

### W_o is an ADDITION to ACT, not an adaptation of it

ACT's observation is a **single timestep**: `qpos = root['/observations/qpos'][start_ts]`
(`utils.py:37`), `forward(self, qpos, ...)` with `qpos: batch, qpos_dim`
(`detr_vae.py:80`). There is no observation window anywhere in the reference. So any
`W_o > 1` is something we added, and it lands in the same place the LSTM would: it gives
the model history.

**Recommendation, and the reasoning is in the session report: set W_o = 1 for every
condition in the ladder.** BC and chunked BC already use it; keeping it at 1 for ACT and
ACT-LSTM makes ACT faithful to the reference and makes each rung of the ladder add exactly
one thing — chunking, then the CVAE, then recurrence. A window would give the transformer
the history the LSTM is meant to supply and would confound RQ3 with the very mechanism it
is testing. The Stage 3 ambiguity curve is consistent with this: on scripted data a longer
window bought no measurable reduction in action ambiguity at all.

---

## 2026-09-21 — ACT implemented, state-only, against the pinned reference

`g1_model/act.py`, 29 tests in `g1_model/test_act.py`. The row-by-row table is
`docs/ACT_CORRESPONDENCE.md`; this entry records what reading the reference cost
us in practice and the two numbers a later session must not re-derive.

### The decoder-layer observation, stated descriptively

`detr_vae.py:131` reads `hs[0]`. `transformer.py:76` returns
`(num_dec_layers, bs, num_queries, d)`, so index 0 is the FIRST decoder layer's
output, while `dec_layers = 7` (`imitate_episodes.py:55`, paper Table III).
Measured on commit 742c753: backward through `hs[0]` gives decoder layer 1 a
gradient of L1 7.41e-05 and layers 2-7 exactly 0.0.

**We build seven and read index 0, exactly as the reference does.** That is
fidelity by construction: reading `hs[-1]` would be a deeper, different model,
and an RQ2/RQ3 result obtained with it could not be attributed to ACT's design.
The consequence is on the record rather than corrected: **44.5% of ACT's
72,534,998 parameters sit in decoder layers 2-7 and receive no gradient.** This
is an observation about the published implementation, not a claim that it is a
defect - only that our parameter count and VRAM figures include weights that do
not train, and any "ACT has 72.5M parameters" statement must carry it.

### beta: the reduction mismatch, measured, and DEFERRED

The reference reduces with `(all_l1 * ~is_pad).mean()` (`policy.py:31`) - padded
entries zeroed, then divided by the FULL element count including padding and all
14 dims. Ours divides by contributing elements (real timesteps x 16 trainable
dims). The scales differ, so the reference's beta does not carry the same L1:KL
balance in our model.

Measured 2026-09-21, 7,628 real samples at K=100 with the trained chunked-BC
checkpoint, decomposed because a single ratio is misleading:

| | L1 |
|---|---|
| ours (16 dims, real timesteps) | 0.042570 |
| reference reduction, applied as-is | 0.073598 |
| reference reduction, **fair** | 0.028951 |

Applied as-is the ratio is 0.578 (implying beta'=5.78), but that is an artifact:
our model emits 22 dims and is never penalised on 6 of them, so their error is
unconstrained and the reference's reduction averages it in. A model actually
trained under the reference's reduction would learn those dims - five are
exactly constant (std 0.0) and `a_gR` is bit-identical to `a_gL` - so the fair
comparison gives them for free:

    ours / reference (fair) = 1.4704   ->   beta' = 14.70

Cross-checked against the pure reduction arithmetic, which is model-independent:
`(n_real x 16) / (B x K x 22) = 0.6801`, and `1/0.6801 = 1.470`. The two agree.

**beta = 10 (the reference's value) is used, and 14.70 is recorded beside it in
every run's metadata.** The choice is deferred because the overfit-10 gate cannot
discriminate between them - on ten episodes the KL term is small and either value
overfits - so it waits for a validation signal that can. NOT rescaled silently.

### The 4 GB ceiling is not a number, it is a range that depends on the desktop

A4, and the finding is sharper than expected. ACT at K=100, hidden 512, ff 3200
does not OOM when it exceeds VRAM on this Windows machine - it spills to shared
system memory and **collapses in throughput**, which is far harder to notice than
a crash. Measured on the RTX 3050 Laptop (4096 MiB):

| batch | GPU nearly idle | GPU with 3355 MiB used by other apps |
|---|---|---|
| 8 | 132.6 ms/step, 60.3 samples/s | 332.6 ms/step, 24.1 samples/s |
| 16 | 206.8 ms/step, 77.4 samples/s | 790.0 ms/step, 20.3 samples/s |
| 32 | 362.7 ms/step, **88.2 samples/s** | 19398 ms/step, **1.6 samples/s** |
| 48 | 2322.8 ms/step, 20.7 samples/s | - |
| 64 | 7115.3 ms/step, 9.0 samples/s | - |

So the honest answer to "largest batch that fits in 4 GB" is **32 on an idle GPU
(3366 MiB peak allocated), 8 under a realistic desktop load**, and the failure
mode in between is a silent 12x slowdown rather than an error. Strict determinism
(`use_deterministic_algorithms(True)`) costs a further ~15% (21.8 s vs 19.0 s per
step under memory pressure) and is kept.

**Chunked BC used batch 256.** ACT cannot. Since the final comparison requires an
identical training configuration across all four models, a batch size forced by
ACT becomes the batch size for BC and chunked BC too, and both would need
re-running at it. Nothing was re-run; this is a decision for Charles.

### What the gate was run under, and what it does not license

The gate ran at **batch 8** and **lr 1e-3**. The lr is BC's provisional value,
inherited through `BCConfig` by the shared runner - it is NOT ACT's published
1e-5 (`README.md:77`, paper Table III). That is correspondence row 36, which is
marked gate-blind and UNRESOLVED. A re-run at 1e-5 is the obvious next step and
was deliberately not done in the same session as seeing the gate result, because
changing a hyperparameter after seeing a gate outcome is what the protocol
forbids.

Note also that at batch 8 an epoch is 954 optimizer steps against chunked BC's 30
at batch 256, so epoch counts are NOT comparable between the two runs and only
step counts are.

### THE GATE FAILED, and the diagnosis is posterior collapse

Overfit-10, K=100, W_o=1, batch 8, lr 1e-3, beta 10, 12 epochs (11,448 optimizer
steps), 2350.9 s:

    train error   0.466184
    reference     0.044657   (W_o=1, K=100, 10 episodes)
    ratio         10.4393    -> FAIL

**The reference is bit-identical to chunked BC's 0.044657**, which is the correct
outcome: W_o and K are unchanged, so the observation space and the prediction
target did not move when the architecture did. That much of the plumbing is right.

The KL term tells the story, and it is only visible because the loop logs `l1`
and `kl` separately:

| epoch | recon | KL |
|---|---|---|
| 1 | 0.494427 | 0.193 |
| 2 | 0.468553 | 0.001 |
| 3 | 0.467091 | 0.001 |
| 9 | 0.466338 | 0.00001 |
| 12 | 0.466184 | 0.00000 |

**The KL collapsed to zero within two epochs and the reconstruction then froze.**
That is textbook posterior collapse: the encoder is driven to the prior, z carries
no information, and what remains is chunked BC with 51x the parameters and a dead
encoder. The final reconstruction, 0.4662, sits between the ZERO baseline (0.6402)
and the COPY baseline (0.4098) - the model learned approximately the mean pose and
stopped.

NOTHING WAS CHANGED TO FORCE A PASS. Two hyperparameters are the obvious
suspects, and both are correspondence rows already marked UNRESOLVED, so neither
was touched after seeing the result:

- **lr = 1e-3** was inherited from `BCConfig` by the shared runner. ACT's
  published value is **1e-5** (`README.md:77`, paper Table III) - 100x lower.
  A post-norm transformer of 72.5M parameters at 1e-3 with no warmup is the
  likeliest root cause of a model that barely trains at all. Row 36.
- **beta = 10** at our reconstruction scale. The D5 measurement compared balances
  at CONVERGED loss (~0.029); at initialisation the reconstruction is ~0.5, so
  the weighted KL (1.93) is roughly 4x the reconstruction term and the optimizer
  kills the KL first. That the measured beta'=14.70 points HIGHER makes this
  worth stating plainly: the 1.4704 ratio is a statement about balance at
  convergence and says nothing about collapse dynamics at initialisation. Row 32.

The next session's first experiment is a re-run at lr 1e-5, unchanged in every
other respect. If the KL survives and the reconstruction falls, the cause was the
learning rate; if the KL still collapses, beta needs a schedule or a floor and
that is a Chapter 3 disclosure, not a tuning choice.

---

## 2026-09-21 — ACT at lr 1e-5: the collapse was the learning rate; the gate still fails

ONE variable changed from the lr-1e-3 run: `lr` 1e-3 -> 1e-5. Proven by diffing
the two runs' `metadata.json`: the only differing `TrainConfig` field is `lr`;
model (72,534,998 params), loader, data seeds, baselines and seed are identical.
Runs: `runs/20260921-121515_act_overfit10_K100` (1e-3) and
`runs/20260921-151816_act_overfit10_K100` (1e-5). Batch 8, beta 10, weight decay
0.0, 12 epochs = 11,448 optimizer steps, both.

### The KL trajectory, reported on its own

| epoch | recon (1e-3) | KL (1e-3) | recon (1e-5) | KL (1e-5) |
|---|---|---|---|---|
| 1 | 0.494427 | 0.193 | 0.375246 | 0.50008 |
| 2 | 0.468553 | 0.001 | 0.283309 | 0.22377 |
| 3 | 0.467091 | 0.001 | 0.235370 | 0.14713 |
| 6 | 0.466541 | 0.0003 | 0.181994 | 0.04733 |
| 9 | 0.466338 | 0.00001 | 0.153455 | 0.02411 |
| 12 | 0.466174 | 0.00000 | 0.138119 | 0.01509 |

**At lr 1e-3 the latent collapsed within two epochs and reconstruction froze. At
lr 1e-5 it did not collapse** - KL is 0.01509 at epoch 12 against 0.00000 - and
reconstruction fell 63% (0.375 -> 0.138) and was still falling (-2.8% in the last
epoch). So the lr-1e-3 failure was the learning rate.

**But the latent is weakly used, and its use is declining.** KL falls
monotonically and roughly geometrically late in the run (~x0.85 per epoch), and
0.015 nats summed over 32 latent dims is very little information. At epoch 12
the weighted term beta*KL = 0.151 is LARGER than the reconstruction term (0.138):
the KL penalty still dominates the objective, which is why the optimizer keeps
spending the latent. This is reported as a finding about a state-only CVAE, not
as a failure to fix. No annealing, free bits, or other collapse remedy was
applied.

### THE GATE SCORED THE WRONG QUANTITY FOR ACT

`tools/train_bc.py` scores `res["final_train_loss"]`, which for ACT is the TOTAL
loss, reconstruction PLUS beta*KL. The neighbour-ambiguity reference is a
reconstruction quantity - mean |action difference| over trainable dims - so the
comparison put KL nats into an action-unit test. BC and chunked BC have no KL, so
there it made no difference; at lr 1e-3 it was right by accident, because KL had
collapsed to zero.

| | value | ratio vs 0.044657 |
|---|---|---|
| reported by the gate (total loss) | 0.289004 | 6.47 |
| correct: reconstruction only | 0.138119 | **3.09** |

**FAIL either way.** The gate code was NOT changed in this session (the session
was scoped to one variable); the fix - score `recon_l1`, which `train()` already
logs, exactly as `evaluate()` already does for validation - is recommended and
awaits Charles. `gate.json` for the 1e-5 run therefore records ratio 6.47; this
entry is the correction.

### TR28 closed structurally, and the second leak it exposed

ACT now states its own optimizer config: `ACTConfig.lr` has NO default (an
unstated lr is a `TypeError`), and `train.assert_optimizer_source` compares what
a model DECLARES (`optimizer_config()`) against the `TrainConfig` it is handed and
raises before a single step on any disagreement. The runner builds each model's
own config and derives the `TrainConfig` from it.

Running the guard against the old wiring found a SECOND leak: `weight_decay`. ACT
declares the reference's 1e-4 (`main.py:17`); the runner had been handing it 0.0.
Every value that reached ACT from outside, enumerated:

| value | came from | reference | status |
|---|---|---|---|
| lr | `BCConfig` default 1e-3 | 1e-5 | LEAKED, now stated |
| weight_decay | runner hardcode 0.0 | 1e-4 | LEAKED, now stated (0.0 at the gate, by design) |
| optimizer | `BCConfig` default | AdamW | same value, now stated |
| batch_size | CLI via `BCConfig` | 8 | routed, stated on CLI |
| obs_window, chunk_size | `BCConfig` | - | shared by design (D1, D2) |
| grad_clip | `TrainConfig` default 1.0 | none | NOT a model declaration; row 40, unresolved |
| seed, determinism, workers | `TrainConfig` defaults | - | loop settings, correctly shared |

`grad_clip` is the one still arriving by default. It is a loop setting rather
than a model declaration, so the guard does not cover it; the reference applies
none. Row 40, unresolved, identical across models.

### The epoch budget had no recorded reason (TR28's family)

BC's gate ran 300 epochs because 300 was the argparse default; ACT's ran 12
because a wall-clock cap was typed on the command line. No run recorded why.
`--epochs` and `--budget-reason` are now both REQUIRED, and each run's metadata
records `epoch_budget`, `steps_per_epoch`, `optimizer_steps` and the reason.

### What "2000 epochs" means - the two codebases disagree by ~760x

ACT's published recipe is 2000 epochs at batch 8 (`README.md:76-77`). The
reference's epoch is NOT ours:

- ours: every tick of every episode - 7,628 samples, 954 steps at batch 8, on 10
  episodes;
- theirs: `__len__` is the number of EPISODES (`utils.py:21`) and each item draws
  ONE random start tick (`utils.py:35`). With 50 episodes x 0.8 train = 40
  (`constants.py:8`, `utils.py:114`), an epoch is 40 samples = 5 steps, and 2000
  epochs = **10,000 optimizer steps in total**.

**The lr-1e-5 run took 11,448 steps - 1.14x the reference's ENTIRE training - and
reconstruction is still 3.09x the ambiguity reference.** So "we did not train
long enough" is weaker than it looks: we have already given ACT more updates than
its authors did. Against that, the reference's task is different (50 episodes,
a 2 s horizon at 50 Hz, 1,200 image tokens), and reconstruction was still
falling here. Both readings are recorded; neither is settled.

### Compute cost (Part D), measured at batch 8, idle GPU, strict determinism

| variant | params | ms/step | peak VRAM |
|---|---|---|---|
| as built (h512, ff3200, 7 dec) | 72.5M | 140.9 | 1752 MiB |
| decoder layers 2-7 removed | 40.2M | 71.1 | 927 MiB |
| h256, ff1024, 1 dec | 7.5M | 48.4 | 291 MiB |
| h128, ff512, 1 dec | 1.9M | 47.2 | 165 MiB |

The gate epoch measured 143.0 s = 149.95 ms/step effective, i.e. 9.1 ms/step of
loader overhead over the pure-compute figure.

**Decoder layers 2-7 are 44.5% of parameters and 49.5% of step time, and removing
them is BIT-IDENTICAL**: with layer 1's weights shared, a 7-layer model read at
`hs[0]` and a 1-layer model give max |difference| exactly 0.0 in inference output,
training output, loss, and every gradient over the shared parameters. It is a
pure compute saving, not an architectural change in any behavioural sense.

Reducing width barely helps below that: 71.1 -> 48.4 -> 47.2 ms/step. The floor
near 47 ms is not width - it is the K=100 decoder sequence, the 102-token CVAE
encoder, kernel-launch overhead and strict determinism. No rule for "proportionate
to a two-token input" exists in the source; the two reduced sizes are measurement
points, not a recommendation derived from it.

Wall time, as built:

| | 10 eps | 32 eps | 150 eps |
|---|---|---|---|
| 2000 OUR epochs, one run | 3.3 days | 10.5 days | 49.3 days |
| 2000 OUR epochs, twelve runs | 39.7 days | 126.2 days | 591.7 days |
| 2000 REFERENCE epochs, one run | 6.2 min | 20.0 min | 1.6 h |
| 2000 REFERENCE epochs, twelve runs | 1.2 h | 4.0 h | 18.7 h |

With decoder layers 2-7 removed, every figure roughly halves.

**Feasibility, plainly:** twelve runs of 2000 of OUR epochs are NOT feasible on an
RTX 3050 Laptop at any dataset size - 40 days at the smallest. Twelve runs at the
reference's own step budget ARE feasible - under a day even at 150 episodes. Which
of the two the thesis means by "2000 epochs" is the decision that sets the
schedule; the architecture is secondary to it.


---

## 2026-09-21 — Resumable, survivable training; the killed ACT run

The step-budgeted ACT convergence run started 16:14 (`runs/20260921-161407_act_overfit10_K100`)
was killed at **step 113,000** (epoch 119) by a CUDA out-of-memory error raised inside
`clip_grad_norm_` - another process took GPU memory; the model itself needs 927 MiB. Window
times had risen from ~73 s to 80-92 s over the preceding five windows, the same shared-memory
pressure signature measured earlier. It was NOT stopped by the stopping rule (relative
improvement over the trailing 10k steps was still 4.68%) and did NOT reach the 200,000-step
cap. Because result.json and gate.json were written only at the end, the 2 h 19 min run left
no verdict. At the kill: recon_l1 0.060190, reference 0.044657, ratio 1.348, still falling;
KL 5.23e-05.

### What best.pt holds (measured)
Weights (40,226,006 parameters plus the 52,224-element fixed `pos_table` buffer), the model
config, and run provenance. **No optimizer state, no RNG state, no step counter.** Its stored
total loss (0.060713131691638535) matches the step-113,000 metrics row EXACTLY, and that row is
the run's global minimum reconstruction - so best.pt is the last window before the kill.

### Resume (`train.Resume`, `--resume-from`)
- **Full state** - `state.pt`, written every window: weights, AdamW state (both moments and
  its step count), every RNG stream (torch CPU and CUDA, numpy, python), the data-order
  generator at the start of the current pass and how many batches of it were done, the
  history, best value and elapsed time. Continuation is **bit-exact**:
  `test_full_state_resume_is_bit_exact` stops a dropout-bearing ACT mid-pass and shows the
  resumed curve equals the uninterrupted one to the bit, and
  `test_resume_actually_depends_on_the_restored_state` shows wiping the optimizer state
  changes it (so the first test is not vacuous). There is no LR scheduler in this loop;
  `scheduler=None` is recorded rather than implied.
- **Weights only** - `best.pt` / `last.pt`. The step is identified by the exact loss match;
  history and config come from the prior run's own files. NOT restored: AdamW's moments (they
  restart at zero with fresh bias correction, so the first steps are sign-like steps of size
  ~lr and a short transient is expected), the RNG streams, and the position within the data
  pass. The curve continues from the resume point but is not the curve the uninterrupted run
  would have drawn. The resumed run's metadata records the kind and each loss.
- Both refuse a resume whose training config (lr, weight decay, optimizer, batch, clip, seed,
  window, stop rule, determinism) or architecture differs. A resumed run writes to its own
  directory with the prior segment's history copied in (tagged `segment`), leaving the killed
  run's directory untouched as evidence.
- Cost: state.pt is 461 MiB and takes ~1.2 s to write, 1.5% of a 73 s window.

### Survivable runs
Every window now appends metrics.jsonl and rewrites result.json (status "running") and
gate.json (the PROVISIONAL verdict at that step) with write-then-rename, so a kill mid-write
cannot truncate them. A Python-level failure - an out-of-memory error is one - writes status
"crashed" and the reason before re-raising (`test_a_crash_leaves_the_verdict_and_a_resumable_state`
injects one mid-step and reads result.json from disk while the run is still alive). A hard OS
kill cannot be caught; the last window's files then say the step at which the run was last alive.

## 2026-09-22 — The gate scores the DEPLOYED function. ACT PASSES at 0.920.

The converged ACT run (`runs/20260922-153630_act_overfit10_K100`, lr 1e-5, beta 10, one decoder
layer; resumed weights-only from step 113,000 of the killed run; stopped by the stop rule at
**195,000** steps) reported recon 0.050886 against the reference 0.044657, **ratio 1.140, FAIL**,
with KL 1e-05. That number was a TRAIN-MODE WINDOW MEAN, and the gate should never have scored it.

### What the logged number was (code facts)
- `train()` calls `model.train()` every epoch and again after evaluation in `_window_row`; the
  logged `recon_l1` is the running mean of per-step training losses over the window, while the
  weights move.
- For ACT that means **dropout 0.1 active** (`act.py DROPOUT`, reference `main.py:43`) and z
  **sampled from the posterior of an encoder that read the target chunk** (`loss_terms` passes
  the target; `reparametrize` samples in either mode).
- Chunked BC has **no dropout at all** (`BCConfig.dropout = 0.0`, and the gate forces 0.0), so it
  was scored fairly by accident. The reference is a nearest-neighbour spread of the data: no
  model, no dropout, no sampling.
- The reference ACT validates under `policy.eval()` (`imitate_episodes.py:343`) and deploys with
  z = 0, the encoder not run (`detr_vae.py:113`; paper §IV-B).
- The old `train.evaluate()` was NOT the fix: in eval mode it still went through `loss_terms`,
  so the encoder still read the target. Inert here, since the latent had collapsed, but it would
  leak the answer to a working CVAE.

### Measured (no training): same 10 episodes (seeds 0-6, 8-10), K=100, W_o=1, `masked_l1`
| converged ACT | train mode, posterior z | train mode, z=0 | eval, posterior z | **eval, z=0 (deployment)** |
|---|---|---|---|---|
| best.pt (185k) | 0.050624 | 0.050460 | 0.041913 | **0.041931 (0.939)** |
| last.pt (195k) | 0.050720 | 0.050569 | 0.041127 | **0.041081 (0.920)** |

Stochastic rows are the mean of 5 passes (std ≤ 1.7e-4). **All of the gap is dropout**: dropout
off moves 0.0507 → 0.0411; z = posterior vs z = 0 moves less than 2e-4. For chunked BC, train
mode = eval mode exactly (difference 0.0).

### The fix (applied, tested)
- `train.score_deployment(model, ds)` is THE gated number: one pass, `no_grad`, `model(obs)`
  with the observation ALONE. The target is used only by `masked_l1`, after the prediction
  exists. `_deployment_guard` enforces eval mode on every submodule for the duration: a pre-hook
  raises if any module runs in train mode, and a pre-hook on every module the model declares in
  `TARGET_READING_MODULES` raises unconditionally. A model with an `encode` method that declares
  nothing is refused. ACT declares `cls_embed`, `encoder_action_proj`, `encoder_joint_proj`,
  `latent_proj` and `encoder`. `cls_embed` is read via `.weight`, so no hook can fire on it; the
  other four run on every `encode` call, which is what makes the encoder unreachable.
- Batches are cut by index, not by a DataLoader: a DataLoader draws its base seed from the GLOBAL
  generator even unshuffled, and scoring every window would then shift the training run's dropout
  and shuffle streams. Measured: a 40-step dropout-bearing ACT curve is **bit-identical** at HEAD
  and with the fix.
- **The gate** scores `score_deployment` on the FINAL weights, in one pass after training.
  The per-window provisional `gate.json` scores the weights at that window. `ambiguity.Quantity`
  gains a `measured` field, and `gate()` refuses anything not `MEASURED_AT_DEPLOYMENT`,
  including an unstated measurement. The train-mode window mean is labelled
  `MEASURED_TRAIN_MODE_WINDOW` and logged beside it, never gated.
- **Selection** uses the same quantity: `best.pt` is the window with the lowest deployment
  score (validation set if given, else the training set; `train.SELECTION_CRITERION`, recorded
  in every best.pt and state.pt). On the OLD criterion both best.pt files scored WORSE than
  their last.pt: chunked BC 0.043962 vs 0.042570, ACT 0.041931 vs 0.041081. A resume from a
  state chosen on the old criterion restarts selection and says so.
- `evaluate()` (validation) now delegates to `score_deployment`; `forward_loss` serves the
  training step only.
- NOT changed: the STOP RULE still monitors the train-mode window means (`recon_l1`,
  `train_loss`). It asks whether optimization is still making progress, which is a training
  question; changing it would change when future runs stop.
- Cost: ~2.7 s per pass over the 7,628 gate samples for ACT, ~3.7% of a 73 s window.
- Tests: `test_train` +10 (scoring ignores the mode it is handed; refuses a forward that flips
  back to train mode; never hands the model the target; cannot reach the ACT encoder, with a
  check that the posterior path really does differ so the test is not blind; the declaration
  matches `encode`; an undeclared encoder is refused; RNG untouched; selection and gate use one
  quantity, re-derived from the files; old-criterion resume restarts selection; the scoring
  path is structurally separate). `test_ambiguity` +2 (the gate refuses a train-mode or
  unstated measurement; only `score_deployment` stamps a gateable quantity).

### Every gate.json on disk rewritten (`tools/train_bc.py rescore-gate`, NO TRAINING)
The dataset is rebuilt from each run's own metadata. The reference is recomputed and must
equal the recorded one, or nothing is written. The old gate.json is kept inside the new one
under `superseded`.

| run | old gate.json | corrected (deployment) | verdict |
|---|---|---|---|
| 072043 BC K=1 | 0.009200 (0.721) | 0.009512 / 0.012764 = **0.745** | PASS, unchanged |
| 072254 chunked BC K=100 | 0.042763 (0.958) | 0.042570 / 0.044657 = **0.953** | PASS, unchanged |
| 121515 ACT lr 1e-3, 7 dec | 0.466184 (10.44) | 0.466052 = **10.436** | FAIL, unchanged |
| 151816 ACT lr 1e-5, 12 ep | **0.289004 (TOTAL loss, pre-TR29)** | 0.117054 = **2.621** | FAIL, unchanged |
| 161407 ACT killed at 113k | none (killed) | best.pt 0.053488 = **1.198** | FAIL, provisional |
| **153630 ACT converged** | 0.050886 (1.140) FAIL | **0.041081 = 0.920** | **FAIL → PASS** |

161407's final weights were never saved; its gate.json scores best.pt, says it was selected
on the old criterion, and is marked `final: false`. 121515's checkpoint predates TR28, so
`ACTConfig.lr` was supplied from its own TrainConfig; lr does not enter the forward pass, and
the gate.json records this. 065658 (BC K=1) has no recorded reference and was not rescored; its
checkpoints score identically to 072043's. `runs/` is gitignored: these rewrites exist on this
disk only.

### The latent collapsed, and that is the EXPECTED outcome on this data
KL is 1e-05 in the log and ~4e-06 in eval mode; deployment at z = 0 matches z = posterior mean to
6 decimals. So ACT passes as a transformer chunked-BC with an inert CVAE. **Reading:** the CVAE
latent exists to encode the STYLE of a demonstration, the variation a demonstrator introduces
that the observation does not determine. The scripted demonstrator is deterministic given its
spawn, so there is no style variation for z to carry, and posterior collapse is what the
objective should find. **This is a PREDICTION to test, not a defect to fix:** on piloted
teleoperation data (one human, varying speed, hesitation, approach), the KL is predicted to stay
above zero and the z = 0 vs posterior-mean gap to open. If it collapses on piloted data too,
that is the finding, and beta (10; balance-matched 14.70, which points further toward collapse)
becomes the live suspect. NOT tested; no beta change made. Consequence for RQ2: on scripted data,
ACT vs chunked BC cannot isolate the CVAE, because there is nothing for the CVAE to do.

## 2026-09-22 — CLAUDE.md §8 ARCHIVE: retired Phase 1–3 decisions and resolved §10 issues

Retired under the CLAUDE.md §14 retirement policy, adopted today with the cap raised 300 → 400. Each entry is
reproduced VERBATIM as it stood in CLAUDE.md, followed by where its content still lives. A pointer line stays in
CLAUDE.md §8 (or §10) for each. Kept in CLAUDE.md, with the reasons reported to Charles: 2026-09-15 grasp without
the base lock (open question); 2026-09-11 schema, phase vocabulary, WALK_IN and dataset design (do-not-re-open
items and plans for work not yet done); 2026-09-09 walking place (the +28 to +31 mm x-bias disclosure is still
owed); 2026-09-09 O20/O21 ("rotating the offset alone scored 10/10 → 3/10" has no other home); 2026-09-08 D11 + Q6
(Q6 is cited by §1 and is a do-not-re-open item).

### 1.

- 2026-09-15 — **OBJECTIVE 1 DEMONSTRATED.** Live operator, ZED, stepped physics, full task. Difficulties reported and the response to each:
  piloting into the lock window is hard (overlay rewritten to give ACTIONS, not measurements); walking/turning felt slow (`KeyboardCommand`
  runs well under the validated envelope); sim ran below real time with tracking active (measured 37.4%, fixed below).

**Still lives in:** §3 (`teleop under stepped physics, full task by a live operator`) and §13 carry the fact; the three operator-reported difficulties were each answered in code (overlay, `KeyboardCommand`, the IK throughput fix).

### 2.

- 2026-09-15 — **IK throughput.** `mj_forward` in the solver loop → `mj_kinematics` + `mj_comPos`; everything the solver reads is
  bit-identical, arm trajectories bit-identical on a real ZED take, sim-to-wall 37.4% → 128.2%. Before the fix the IK was 97.4% of
  `controller.step` (34.33 ms) against retargeting 0.14 ms and smoothing 0.57 ms. Next bottleneck: renderer (31–42% of wall), camera (~21 Hz).

**Still lives in:** `g1_teleop/ik.py` carries the rationale and the measured bit-identity (`tools/teleop_throughput.py --verify`).

### 3.

- 2026-09-15 — **D18 adopted** (B-prime) after a measured A/B and one revert; `<contact><exclude>` pairs, not contype bits, so hand↔hand survives.

**Still lives in:** §7 D18 carries the decision; `g1_teleop/contact_contract.py` explains exclude pairs versus contype bits.

### 4.

- 2026-09-11 — **O26 MITIGATED** by the staged raise: wedge gone, wrist error 1.418 → 0.001 rad, predicate gate 24/40 → 40/40. **The collision
  is not fixed** (§10).

**Still lives in:** §10 O26 carries the status (wedge gone, collision not); the 24/40 → 40/40 figures are in §10's Phase 1 gate item.

### 5.

- 2026-09-10 — **Constant-dim mask measured**: 6 of 22 action dims excluded, 16 trainable; no state dim is constant. **Base-lock predicate**
  defined from the 47-D state, measured, validated closed-loop, enabled: settled test is one full `GAIT_PERIOD`, debounced 5 ticks, latching
  edge trigger, with a `to_goal` guard separating lock from release.

**Still lives in:** §6 and `g1_data/spec.py` carry the mask; the `g1_data/phases.py` docstring carries the predicate (one `GAIT_PERIOD`, 5-tick debounce, `to_goal` guard); TR20 stays in §9.

### 6.

- 2026-08-23 — Q1–Q5: palm-pad gripper; `KeyboardCommand` over the pelvis trigger (TR1); 25 Hz recording with a 50 Hz locomotion loop;
  `d_place = 0.10 m` plus a resting clause; waist pinned (D10); learning code at the repo root; plain ACT as a third condition (D8).

**Still lives in:** §7 D4/D6/D8/D10 and TR1 carry them; `d_place` is `g1_data/success.py` `place_radius` (Q4).

### 7.

- **O12. CLOSED** — Q7 is answered: the robot DOES walk during demonstrations (12/12 scripted walking place, and a live operator walked in), so the
  arm's-reach fallback is off the table and loco-manipulation stays in the contribution (PLAN.md).
  **O10, O14–O16, O18, O20–O24. RESOLVED** — see §8 and `NOTES.md`; O10's cap now comes from the measured 694–846 distribution, spawn-dependent
  rather than schedule-derived.

**Still lives in:** §10 item, resolved. §14 permits removing resolved issues; archived rather than deleted. O12's answer also lives in PLAN.md and in §3 (the robot walks in every episode).

---

## 2026-09-29 — Phase 4 closed: all four models pass overfit-10 at W_o = 12 (NVIDIA laptop)

The first results under O34 Option B: every number below comes from the NVIDIA laptop (RTX 3050 Laptop, 4 GB), with the pinned
environment verified before the runs: Python 3.10.11, mujoco 3.6.0, numpy 1.26.4, torch 2.11.0+cu126 (CUDA 12.6, cuDNN 91002),
opencv 4.11.0. Code at commit `ab257e5`. Data: the 40 scripted episodes recorded on THIS laptop (`data/synthetic/`), gate on the
first 10 training seeds (0-6, 8-10, 7628 samples), `norm_stats_v1.npz` fitted on the training split. Run directories are in
`runs/` (git-ignored).

### Pre-flight
- All suites pass: `g1_data.test_{spec,contact_contract,dataset,dropout}`, `g1_model.test_{loader,ambiguity,train}`,
  `tools.test_keypoint_recording` (192 tests), and `g1_model.test_act` 47/47. `test/test_g1_control.py` not run (stale, O7).
- The ACT golden fingerprint (`test_use_lstm_false_is_act_exactly_as_it_was_before_the_flag`), recorded on torch 2.14 CPU, PASSES
  here on torch 2.11 CUDA: the parameter hashes are exact and the outputs are within the test's 1e-6 tolerance.

### Gate results (W_o = 12; ratio < 1 passes)
| model | budget | train error (deployed) | reference | ratio | run |
|---|---|---|---|---|---|
| BC (K=1) | 300 epochs, batch 256 (9000 steps) | 0.010013 | 0.015836 | **0.632 PASS** | `20260928-221450_bc_overfit10_K1_W12` |
| chunked BC (K=100) | 300 epochs, batch 256 (9000 steps) | 0.038959 | 0.054265 | **0.718 PASS** | `20260928-221835_bc_overfit10_K100_W12` |
| ACT (K=100) | 200k-step cap, batch 8, stop rule 10 x 1000 at 1% | 0.039071 | 0.054265 | **0.720 PASS** | `20260928-222316_act_overfit10_K100_W12` |
| ACT-LSTM (K=100) | identical to ACT, same `--budget-reason` | 0.032544 | 0.054265 | **0.600 PASS** | `20260929-022601_act_lstm_overfit10_K100_W12` |

Budgets copied from the W_o = 1 gates they replace, so only W_o changed. Wall time: ACT 14,554 s (13.74 steps/s), ACT-LSTM
15,675 s (12.76 steps/s); ACT used 2.3 of 4 GB.

### Neither ACT run converged
Both stopped by the 200,000-step HARD CAP, not by the stop rule. Improvement of the best windowed mean over the last 10 windows
against the best before them (the rule's own quantity; it stops below 1% for BOTH monitors):

| run | recon_l1 | train_loss |
|---|---|---|
| ACT | 0.046795 -> 0.046035, 1.62% | 0.046922 -> 0.046144, 1.66% |
| ACT-LSTM | 0.039754 -> 0.038912, 2.12% | 0.039864 -> 0.038983, 2.21% |

The W_o = 1 ACT gate DID stop by the rule, at 195,000 steps. PLAN.md's Phase 4 exit criterion ("train to convergence") is
therefore NOT shown for ACT or ACT-LSTM, nor for BC and chunked BC, which ran a fixed 300 epochs with no stop rule (as at
W_o = 1). The gate verdicts stand, because the gate scores the final weights actually trained. **Do not rank the models on this gate.** ACT-LSTM was still improving faster than ACT, a ratio
below 1 means only that the fit is below the observation's ambiguity, and this is training error on 10 scripted episodes, not RQ3.

### What else the runs show
- **The latent collapsed again, in both ACT and ACT-LSTM**: KL 1e-05 throughout, as at W_o = 1 (CLAUDE.md §8 2026-09-22). Expected on
  a deterministic demonstrator (O32). ACT scores the same as chunked BC (0.720 vs 0.718), as the audit predicted: on scripted data the
  CVAE adds nothing the gate can see.
- **ACT and ACT-LSTM differ ONLY in `use_lstm`**, diffed from the `model_kwargs` saved in both `best.pt` files (every other field equal,
  including the inert `lstm_*` fields). The training configs are identical except `run_name`; the metadata notes differ only in
  `model` and in the regularization statement, which names the LSTM dropout. Parameters: ACT 40,755,414, ACT-LSTM 41,726,166.
- The three K=100 models share one reference (0.054265) because they share one loader configuration, so their ratios are directly
  comparable to each other. BC's reference (0.015836) is its own. None is comparable with the W_o = 1 gates (O31), nor with the
  CPU laptop's W_o = 12 code-test ratios (0.568, 0.630): that laptop recorded its own episodes and the reference differs
  (0.015836 here vs 0.016343 there; O34).

### cuDNN LSTM on the GPU: deterministic, but crashes Python at exit
- **Determinism (the item §8 2026-09-28 left untested).** With `use_deterministic_algorithms(True)`, `cudnn.deterministic = True`,
  `cudnn.benchmark = False` and `CUBLAS_WORKSPACE_CONFIG=:4096:8`: a 2-layer LSTM (47 -> 256, dropout 0.3, train mode, batch 64,
  W = 12), seeded, run forward and backward twice, gives bit-identical gradients and outputs. Small scale only; a full run was not
  repeated to check bit-identity end to end.
- **Exit crash.** Every process that has run a cuDNN LSTM on CUDA exits with `-1073740791` (0xC0000409, a fail-fast) AFTER all its
  work is done: `g1_model.test_act` prints `47/47 passed` and then crashes, twice. A minimal script reproduces it:
  | script | exit |
  |---|---|
  | Linear on CUDA, deterministic | 0 |
  | LSTM on CUDA, deterministic | crash |
  | LSTM on CUDA, NOT deterministic | crash |
  | LSTM, then `gc.collect()` + `synchronize()` + `empty_cache()` | crash |
  | LSTM with `torch.backends.cudnn.enabled = False` | 0 |

  So it is cuDNN's RNN teardown in this build (torch 2.11.0+cu126, cuDNN 9.10, Windows), not our code; `faulthandler` prints
  nothing. **cuDNN is kept ON**: disabling it changes how the LSTM computes, a methods decision not taken here. Consequence: the
  ACT-LSTM gate run "failed" with that exit code while its `gate.json` was complete and `passed = true`. **Judge an ACT-LSTM run by
  its `gate.json` and log, never by its exit code**, and run it with `python -u` so the log is not lost in the crash.
