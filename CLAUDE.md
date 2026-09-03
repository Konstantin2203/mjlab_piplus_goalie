# CLAUDE.md

This file provides guidance to Claude Code (claude.ai/code) when working with code in this repository.

## Overview

This is a [mjlab](https://github.com/mujocolab/mjlab) project for training RL policies for the PiPlus humanoid robot. It uses MuJoCo Warp (GPU-accelerated MuJoCo) with a manager-based API similar to Isaac Lab, and RSL-RL for PPO training.

## Commands

Always use `uv run`, not `python` directly.

```sh
# Train — launch as a background process via Bash run_in_background=true (NOT tmux), auto-select a free GPU via nvidia-smi
# After launch, poll wandb/ dir for new run-YYYYMMDD_HHMMSS-* directories
# (verify timestamp matches current time, as runs take time to initialize).
# Inside the dir, find the run-<id>.wandb file — the ID is in the filename.
# Read the first few lines of that file to find a path like
# logs/rsl_rl/piplus_velocity/2026-04-12_23-56-38 — the last segment is the
# run name. Then prepend a line to runs.log (newest first):
# <name>: <id>: <short summary>
uv run train Mjlab-Velocity-PiPlus --env.scene.num-envs 4096 --gpu-ids '[GPU]'

# Play/evaluate a trained policy — launch as a background process via Bash run_in_background=true (NOT tmux), pick a free GPU via nvidia-smi
# Export CUDA_VISIBLE_DEVICES to a single GPU before launching.
# Prefer unused GPUs; if all busy, pick one with low utilization and free memory.
# When playing multiple runs, always run them SEQUENTIALLY — wait for each to
# finish before starting the next, not in parallel.
CUDA_VISIBLE_DEVICES=GPU uv run play Mjlab-Velocity-PiPlus --wandb-run-path jgueldenstein/mjlab_piplus/<id>

# Sanity-check with dummy agents (no training needed)
uv run play Mjlab-Velocity-PiPlus --agent zero
uv run play Mjlab-Velocity-PiPlus --agent random

# Format and lint
uv run ruff format
uv run ruff check --fix

# Type check
uv run ty check    # fast
uv run pyright     # thorough
```

## Architecture

### Package layout

- `src/mjlab_piplus/robot/` — Robot definition: MuJoCo XML spec, actuator configs (PD gains, effort limits, delay), collision configs, and home keyframe pose.
- `src/mjlab_piplus/tasks/` — Task registration and configs: environment config (observations, rewards, terminations, curriculum) and RL runner config (PPO hyperparameters).


### Task registration

Tasks are registered in `src/mjlab_piplus/tasks/__init__.py` via `register_mjlab_task()`. The package entry point `mjlab.tasks` (declared in `pyproject.toml`) causes mjlab's CLI to discover the task automatically. The registered task ID is `"Mjlab-Velocity-PiPlus"`.

### Robot definition (`piplus_constants.py`)

Three motor series are used:
- **3536** — head joints (still commented out in the MJCF and in the actuator list)
- **4438** — arm joints, enabled via `get_piplus_robot_cfg(with_arms=True)`
- **5036** — leg joints (hip pitch/roll, thigh, calf, ankle pitch/roll), with per-joint tuned PD gains

Each actuator series uses `BuiltinPositionActuatorCfg` with built-in action lag controlled by `ACTUATOR_LAG_MIN` and `ACTUATOR_LAG_MAX` constants (same lag applied to all actuators). The `get_piplus_robot_cfg()` function assembles the full `EntityCfg` with the MuJoCo spec, collision model, and actuator list.

> ⚠️ **`with_arms` changes the DoF count (12 → 20)** and therefore the action
> dim and the joint blocks of the observation. Only the **multi** task uses it.
> `mdp/symmetry.py` carries both layouts (`JOINT_ORDER_12` / `JOINT_ORDER_20`),
> so the mirror follows either — but a task's symmetry class has to name the
> right one. `get_spec(with_arms=False)` deletes the arm joints and their
> actuators from the spec, so the arms stay welded to the torso exactly as
> before.

The `*_selfpad` geoms are declared in `piplus.xml` under the
`self_collision_pad` class, the way the reference declares its own — they are
always in the spec. `get_piplus_robot_cfg(self_pads=True)` is what makes them
live, by adding `SELF_PAD_COLLISION` to put them on contype/conaffinity **bit
2**, so they can only ever touch each other: never the terrain, never the ball,
never the real (bit 1) collision geoms. They are what the multi task's
`self_collision` sensor scores. Because a pad cannot reach the ground, its size
is free — which is the point. Without `self_pads`, `FULL_COLLISION`'s
`disable_other_geoms` leaves them at contype 0 and they cost nothing, which is
how velocity and path see them.

> ⚠️ **A pad the same size as its collision geom is not a bug.** The pad set's
> first job is to *select* which link pairs count as a self-collision; only where
> near-misses matter is the copy enlarged — torso 1.2×, hands 2×, feet 1.3×, the
> rest 1:1, and the upper arms not padded at all. The MJCF says the same next to
> the class definition.

Collision configs (`FULL_COLLISION`, `LEG_ONLY_COLLISION`, `FEET_ONLY_COLLISION`) use regex matching on geom names ending in `_collision[0-9]`. `SELF_PAD_COLLISION` must be applied **after** `FULL_COLLISION`, whose `disable_other_geoms` default would otherwise zero the pads out again.

### Environment config (`piplus_velocity_env_cfg.py`)

The function `piplus_velocity_env_cfg(play=False)` builds a `ManagerBasedRlEnvCfg`. Key design choices:

- **Actor obs**: base angular velocity, projected gravity, joint pos/vel relative to default, last action, gait phase (sin/cos), velocity command. The sensor-derived terms (ang vel, gravity, joint pos/vel) are noised; actions, phase, and command are not.
- **Critic obs**: actor obs + base linear velocity, foot height (from `TerrainHeightSensorCfg`), foot air time, foot contact, foot contact forces. No noise.

> ⚠️ **Symmetry depends on the actor obs layout.** The left-right mirror in
> `symmetry.py` is a list of `Block`s, one per actor obs term (and one per
> sub-command inside a `MultiCommand`), each with its own rule: swap left/right
> joints and negate, plus a sign flip for axial vs. polar quantities — ang-vel
> `[-1,1,-1]`, gravity `[1,-1,1]`, velocity command `[1,-1,-1]`, phase
> half-period shift `[-1,-1]`. **Any change to the actor obs — term order,
> dimensions, or what a term measures — requires editing the block list for
> that task.** Widths are no longer implicit: the mirror is resolved against the
> real observation width on first use and raises with the full block breakdown
> if they disagree, so a drift fails at startup instead of silently mirroring
> the wrong columns. The **critic obs does NOT need a mirror transform**: under
> data augmentation the mirrored sample reuses the original's value/return
> (`V(mirror(s)) == V(s)`), so the value function is only evaluated on the
> original obs.
>
> Run `uv run python -m mjlab_piplus.tasks.mdp.check_symmetry` after touching
> the observations, the commands, or the robot: it checks the joint order and
> the left/right axis mirroring against the compiled MJCF, the block widths
> against each env cfg, and that every mirror is an involution.

- **Sensors**: `ContactSensorCfg` for feet ground contact (ankle roll link subtrees vs. terrain), self-collision sensor, terrain height scan anchored at foot sites.
- **Curriculum**: velocity command ranges ramp up in two stages, from step 0 to step 800 × 24 (`command_vel`).
- **Terminations**: time out (20 s episodes), orientation > 45° (`bad_orientation`). The root-height termination is currently commented out.
- **Simulation**: 5 ms timestep, decimation 4 (→ 50 Hz policy), MuJoCo Warp with 10 solver iterations.
- In `play` mode: curriculum disabled, episode length unbounded, extra air-time metrics added. Push events stay active.

### Falls in the multi task

There is **no getup**. A fall ends the episode (`fell_over`, `bad_orientation`
past 70 deg, the same limit the velocity task uses) and `is_terminated` charges
-200 once. Everything that supported fall recovery was removed: the
`getup_imitation` and `on_ground` rewards, the `fallen_too_long` deadline, the
`fallen`/`getup_success` metrics, and the `GatedRewardTermCfg` wrappers on all
ten walking and safety terms — those gates existed only to fade walking rewards
out while the robot was down, and with falls terminal there is nothing to fade.
The reset is back to the walking task's `reset_base` (`reset_root_state_uniform`)
+ `reset_robot_joints` (`reset_joints_by_offset`) pair, replacing
`reset_fallen_or_standing`.

The getup machinery itself still exists and is still used — see
`mdp/getup.py`, `mdp/imitation.py` and `Mjlab-StandupImitation-PiPlus` below.
It is only the multi task that no longer uses it.

> ⚠️ **`nconmax` is 30**, down from the 120 getup needed. A robot lying on its
> back touches the floor with the whole trunk, both arms and both legs at once
> (~43 contacts). With falls terminal it never reaches those poses, and the
> count is bounded by how many collision geoms can touch a plane at once: the
> measured peak is **19** in any single world across 512 envs x 400 steps of
> standing, of thrashing under random actions, and of being force-tipped to 65
> and 89 degrees. Contacts past `nconmax` are dropped *silently* and look like
> the robot sinking through the floor, so re-measure before trimming further,
> and raise it for anything that puts the robot on the ground on purpose or for
> terrain that is not a plane. Measured cost at 2048 envs: 120 -> 3384 MB,
> 45 -> 2264 MB, 30 -> 2038 MB of process GPU memory.

- **The arms stay actuated** (`with_arms=True`, 20 DoF). They were enabled for
  getup, but they earn their place in walking as a balance aid and in the kick.
  The mirror follows: `PiPlusMultiSymmetry` uses `JOINT_ORDER_20` and mirrors
  the composite command block by block.
- **Self-collision is scored on the pads, with no `secondary`.** A secondary
  *pattern* silently collapses to one geom — `ContactSensorCfg.secondary_policy`
  defaults to `"first"` — so matching `.*_selfpad` on both sides scores every pad
  against the base pad alone and reads ~0 however folded the robot is. Dropping
  the secondary is correct here, not a shortcut: bit-2 isolation already means a
  pad's only possible contact partner is another pad.

### Action scale

The multi task uses mjlab's plain `JointPositionActionCfg` at a uniform
`scale=0.1`, `use_default_offset=True` — `target = default + 0.1 * a`.

Two alternatives were built and measured while getup was in scope, and both are
still available if the action range ever becomes a constraint again:

- **Per-joint `scale` dict.** `BaseActionCfg.scale` accepts `dict[str, float]`
  matched by regex over joint names (`actions.py:64-73`).
- **`QuadraticJointPositionActionCfg`** (`mdp/actions.py`), a signed-quadratic
  map `target = default + sign(a) * scale * a^2`, subclassing
  `JointPositionAction` and overriding only `process_actions`.

> ⚠️ **Scale multiplies the policy's exploration noise as well as its mean.**
> `Policy/mean_std` sits near 1.3 and does not anneal away (`entropy_coef=0.01`
> is the floor), so a uniform 0.5 leaves ~0.65 rad of permanent per-joint jitter
> against ~0.13 rad at 0.1. Measured: a uniform 0.5 run collapsed `posture`
> 0.246 -> 0.001, `foot_gait` 0.186 -> 0.002 and `feet_phase` 0.198 -> 0.005
> against a 0.1 baseline, while running *further* into training.

> ⚠️ **`action_rate_l2` is charged on raw policy output** (mjlab's docstring:
> "Operates on raw policy output"), so the cost of a physical motion is
> `w*(dq/scale)^2`. Raising a joint's scale 5x makes the same motion **25x**
> cheaper to make abruptly — under a uniform 0.5 that silently removed the
> smoothness constraint from walking (`Episode_Reward/action_rate_l2` fell
> -1.74 -> -0.014). **Changing a scale also changes that joint's effective
> smoothness weight by 1/scale^2.**

If you do split the scale per joint, split it by *measured walking swing*, not
by joint range. Rolling out `ewxi1s0n` (uniform 0.1) under a velocity command
gives noise-to-signal per joint, at 0.1 -> at 0.5: `hip_pitch` 0.05 -> 0.23 and
`calf` 0.08 -> 0.38 (they carry the gait's large excursions, +-1.9 and +-1.4
rad, so 0.5 is cheap for them), against `thigh` 0.27 -> 1.35, `hip_roll`
0.35 -> 1.73, `ankle_pitch` 0.23 -> 1.17, `ankle_roll` 0.28 -> 1.37 — those do
small precise work and drown. **`thigh` included, despite its 2.77 rad range**,
which is exactly why range is the wrong criterion.

### Getup by imitation (`mdp/imitation.py`)

Instead of discovering a stand-up from shaped rewards, the fallen robot is paid
for reproducing what an already-trained getup policy would do from the same
state. The teacher is a checkpoint from the reference env in `mjlab_playground`
(`getup_model.pt` at the repo root); `GETUP_TEACHER_CHECKPOINT` names it.

Two things are bridged, and they are the whole module:

- **Observation.** The teacher's actor is a 66 → 20 MLP taking
  `[base_ang_vel(3) | projected_gravity(3) | joint_pos_rel(20) |
  joint_vel_rel(20) | last_action(20)]`. The first four are the *same mjlab
  functions* this env already uses, so they are rebuilt by calling them
  directly — **not** by slicing this env's actor obs, which has extra terms
  (phase, command) in a different layout and is noised. The fifth is the
  **teacher's own** previous output, kept in a buffer here and zeroed on reset;
  carrying it across an episode boundary would feed it the tail of a different
  getup. The reference runner sets `obs_normalization=False` on its actor, so
  there is no normalizer to apply — the loader raises if a checkpoint has one.
- **Action.** The teacher is a `RelativeJointPositionAction`
  (`target = joint_pos + a*0.6`); this env is default-relative
  (`target = default + f(a)`). Comparing raw action vectors would be
  meaningless. Both are converted to a **joint position target in radians** and
  the reward is `exp(-mean_j (Δq)^2 / std^2)` over that. This also makes the
  term indifferent to this env's action scale or to swapping in a nonlinear map.
  `_processed_actions` is read *before* the encoder-bias subtraction, which is
  where the teacher's expression sits too, so the bias cancels.

Joint order is resolved **by name** (`TEACHER_JOINT_ORDER`), not assumed — it
happens to be the identity for all 20 actuated joints, but a reorder on either
side would otherwise scramble the mapping silently.

> ⚠️ **The teacher's `joint_pos` observation is relative to the TEACHER's
> default pose, not this env's.** The reference robot's home keyframe
> ("walkready") differs from ours on 9 of 20 joints — elbows by 0.7 rad, calves
> by 0.2, hips and ankles by 0.1, RMS 0.235 — so subtracting our default (what
> mjlab's `joint_pos_rel` does) offsets the teacher's input by that much.
> Measured: it changed the teacher's action by mean 0.30 (max 1.55), i.e. a
> 0.179 rad error in the joint target it asks for, and cost ~0.036 m of the
> height its getup reaches. `TEACHER_DEFAULT_JOINT_POS` holds the correct pose.
> Note the consequence: following the teacher drives the robot toward *its*
> standing pose, not ours — which in the multi task pulls against `posture`.

> ⚠️ **Rewards run after the physics step, but the action being judged was
> chosen from the pre-step state.** The teacher's target is therefore cached one
> call earlier, from the state the student actually acted on, rather than
> recomputed at reward time. During a getup the joints move ~0.06 rad per 20 ms
> step, and comparing across that gap scored a *perfect* teacher-following
> oracle **0.618** instead of 0.997. An env's first step after a reset has no
> cached target from its own episode and scores 0.

> ⚠️ `std` is 0.3, and should not go tighter. An untrained policy sits ~0.39 rad
> from the teacher; at `std=0.2` that is a reward of 0.018 with gradient 0.44,
> versus 0.17 and 1.60 at 0.3 — the same exponential-saturation dead zone that
> kills `posture` when its std is too tight.

The term is gated to the fallen half with `fallen_gate`: the teacher's env has
no velocity command and it was trained to stand up and *stop*, so ungated it
would fight the walking controller. `on_ground` is now the mirror image — a flat
`always_one` at weight -1.0 through the same `fallen_gate`, so the "is it
fallen" test is the gate rather than something the term re-derives.

### `Mjlab-StandupImitation-PiPlus` — the imitation validation task

`piplus_standup_imitation_env_cfg.py`. A stripped env whose only job is to
answer "does the teacher bridge work": no commands, no gait shaping, no
penalties, no ball, no curriculum, no terminations but the time-out. The
**imitation reward is the entire objective**, so the return is a direct readout
of how closely the student tracks the teacher, uncontaminated by anything else.

Deliberate differences from the multi task:

- **The imitation term is ungated.** Gating it would blind the reward exactly
  when the robot succeeds and stands up. (The multi task no longer uses this
  reward at all — see "Falls in the multi task".)
- **The three shaping terms come from the reference** at its own weights:
  `torso_height` 2.0, `head_height` 1.0, `orientation` 1.0, all ungated (gating
  them on "is fallen" would step the return *down* the instant the robot stands
  up). They sum to 4.0/step; `IMITATION_WEIGHT` matches that total at 4.0.
- **No `on_ground` and no terminations but the time-out.** Being on the floor is
  priced by the height terms falling toward zero there, which is a gradient
  rather than a flat rate.
- **Every env spawns fallen** (`fall_probability=1.0`).
- **The actor obs is exactly the teacher's 66-vector**, so the student can in
  principle represent the teacher and a poor score is evidence about the bridge
  rather than a missing input.

It carries the multi task's **domain randomization** (all 11 startup terms) and
**observation noise + 1-step delay**, verbatim, so a policy that works here is
answering the same sensing and dynamics question it will face there. No
`push_robot`: a shove is something to walk off, and this env's only job is
standing up from the floor.

> ⚠️ **The teacher does not see any of the noise.** `imitation.py` builds its
> observation from true state, so the target stays a clean function of where the
> robot actually is while the student reproduces it from noisy, delayed sensing.
> A teacher fed the same noise would emit a noisy target — variance in the
> reward with no added information.

That extends to the encoder bias, and it matters. `teacher_biased` defaults
**False**. Teacher getup success (fraction of envs above 0.29 m after 300 steps,
256 envs, teacher-following oracle):

| configuration | final base h | success |
|---|---|---|
| no DR, no obs noise | 0.329 | 1.00 |
| no DR, obs noise on | 0.329 | 1.00 |
| full DR minus `encoder_bias` | 0.327 | 0.98 |
| full DR, `encoder_bias` at the reference's ±0.0698 | 0.310 | 0.85 |
| full DR, teacher sees biased position | 0.292 | 0.65 |
| **full DR, teacher sees true position (default)** | **0.312** | **0.84–0.89** |

The teacher's own env in `mjlab_playground`
(`getup/config/pi_plus/env_cfgs.py`) now carries **this same DR set and sensor
noise**, so the next teacher is trained under the conditions it will advise
under. `getup/config/pi_plus/verify_dr_matches_piplus.py` diffs the two configs
term by term and exits non-zero on any mismatch — run it after touching either
side:

```sh
cd ~/mjlab_piplus && PYTHONPATH=~/mjlab_playground/src uv run python \
  ~/mjlab_playground/src/mjlab_playground/getup/config/pi_plus/verify_dr_matches_piplus.py
```

The numbers below predate that change and were measured with `getup_model.pt`
(iteration 200), trained under the playground's *old* randomization.

Two readings. **Observation noise costs the teacher nothing** — it reads true
state, so only the student is affected. **`encoder_bias` is the entire DR
effect**: it is the one randomization that reaches the teacher's input, this env
runs it at ±0.1 against the ±0.0698 the reference trained on, and a persistent
per-joint offset is not something a policy can average away. Feeding the teacher
the true position recovers most of the loss. The residual (0.84 vs 1.00) is the
physical DR — masses, gains, friction — which the teacher genuinely never saw,
and `getup_model.pt` is an early (iteration 200) checkpoint.

Measured, 128 envs x 300 steps, no DR (values are per-step, i.e. `reward_buf / dt`):

| policy | total/step | imitation value | base height start → end |
|---|---|---|---|
| zero action | 1.233 | 0.0003 | 0.398 → 0.092 |
| random action | 1.216 | 0.0003 | 0.398 → 0.089 |
| **teacher-following oracle** | **7.627** | **0.9967** | 0.397 → **0.348** |

The oracle scores 0.997 of a possible 1.0 on the imitation term, ~2500x above
chance, and the teacher driven through this env's default-relative action term
genuinely stands the robot up (0.09 collapsed → 0.31). The bridge is exact: the
student's commanded target matches the teacher's to 2e-8 rad.

Per-term payout, robot held in each pose (max 4.036/step of shaping):

| state | torso_height | head_height | orientation | shaping total |
|---|---|---|---|---|
| flat on the floor | 0.519 | 0.150 | 0.500 | 1.171 |
| standing upright | 2.000 | 1.000 | 1.000 | 4.036 |

So the shaping alone offers 2.87/step for standing up, against up to 2.0/step
for imitating well. A policy that stands *without* imitating out-scores one that
imitates on the floor — intended, but worth knowing before reading a run.

### Viewer GUI (`mdp/push_gui.py`)

mjlab's viser viewer only hands *command terms* a GUI hook
(`CommandTerm.create_gui`), so anything the project wants in the panel has to
ride along on one. `PushGui` (a "Push" folder: six velocity-delta sliders,
±3 m/s linear / ±6 rad/s angular, a heading-frame toggle, and a *Push robot*
button) is built by whichever term owns the panel — `MultiCommand` in the multi
task, `UniformVelocityCommandWithStop` when it runs standalone (velocity and
path). A sub-term under a composite command must skip it (`if
self.joystick_gate is None:`), or the folder appears twice.

The button click arrives on viser's thread, so it only sets a flag; the write
happens in `PushGui.apply`, called from the owning term's `compute`. The push is
the same mass-independent root-velocity delta as the training-time
`push_by_setting_velocity` event. It shows up in `asset.data` only after the
next forward, which is what makes it look like a no-op if you assert on the same
step.

### RL config (`piplus_velocity_rl_cfg.py`)

PPO with asymmetric actor-critic (actor/critic each 512-256-128 MLP, ELU activation). Logs to W&B project `mjlab_piplus`. 24 steps per env per rollout, up to 6 400 iterations, checkpoint every 50 iterations.

Each task's RL cfg carries its own symmetry class from `mdp/symmetry.py`, and
the two enforcement paths are configured independently — `use_data_augmentation`
appends the mirrored samples to every mini-batch, `use_mirror_loss` adds a soft
penalty at `mirror_loss_coeff`:

| task | class | augmentation | mirror loss |
|---|---|---|---|
| velocity | `PiPlusSymmetry` | off | off (coeff 0.5) |
| path | `PiPlusPathSymmetry` | on | on, 0.1 |
| multi | `PiPlusMultiSymmetry` | on | on, 0.1 |

## Editing conventions

- All custom MDP terms (rewards, metrics, curriculums, etc.) go in
  `src/mjlab_piplus/tasks/mdp/` and are wired into the env cfg via
  `pi_mdp.<name>`. Do **not** edit `mjlab/` sources unless the user
  explicitly says to.

## Code style

- Line length: 88 columns.
- Avoid local imports unless necessary for circular import resolution.
- Joint name patterns use regex strings (e.g., `".*_hip_pitch_joint"`) — these are matched by MuJoCo name filters throughout mjlab.
