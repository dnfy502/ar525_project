# MC-PILOT Change History
AR525 Group-3, IIT Mandi

---

## Exploration 2: PyBullet Arm + Noise (mc-pilot-pybullet/)

### Motivation

The `mc-pilot/` and `mc-pilot-elevated/` implementations have a structural weakness as RL demonstrations: the policy outputs a release speed and that exact speed is applied to the ball. There is no gap between "what the policy commands" and "what physically happens." Ball free-flight is deterministic given release velocity, so a non-RL solver could invert the ballistic equations once and achieve near-perfect accuracy. The existing work only shows that RL can learn a known physics model, not that it can cope with real uncertainty.

The paper (Turcato et al. 2025) handles this via Modification 2: gripper delay estimation. The arm's gripper opens with an unknown random delay, perturbing the actual release moment and therefore the actual release velocity. Our simulation-only work skipped this module. Exploration 2 introduces a PyBullet arm + injected noise as the simulated analogue of that stochasticity.

**Goal:** Make the gap between commanded and delivered velocity explicit, so the RL must learn a policy robust to that noise. Also provides a visualisation pipeline (PyBullet GUI, trajectory traces, video recording).

---

### Files added/modified in mc-pilot-pybullet/

`mc-pilot-pybullet/` was created as a full copy of `mc-pilot/` (`cp -r mc-pilot mc-pilot-pybullet`). The original `mc-pilot/` and `mc-pilot-elevated/` are untouched.

#### robot_arm/__init__.py
Empty module marker.

#### robot_arm/arm_controller.py — `ArmController` class

Handles all arm-side operations for one rollout.

**Constructor:** Loads KUKA iiwa7 URDF from `pybullet_data` into an existing client, reads joint limits from URDF, stores iiwa7 hardware velocity limits `[1.71, 1.71, 1.75, 2.27, 2.44, 3.14, 3.14]` rad/s. Default neutral pose `[0, 0.5, 0, -1.0, 0, 0.5, 0]` places EE at approx (0.69, 0, 0.71).

**`plan_throw(v_cmd, release_pos, t_w, t_r, T)`:**
1. IK to `release_pos` using `p.calculateInverseKinematics` (200 iterations, threshold 1e-4, restPoses=q_neutral).
2. Jacobian pseudoinverse: `p.calculateJacobian` → J_lin (3×7) → `qd_release = pinv(J_lin) @ v_cmd`. Scales down uniformly if any joint exceeds its velocity limit.
3. Windup pose: `q_windup = q_neutral + (q_release - q_neutral) * (-0.5)`, clipped to joint limits.
4. Cubic polynomial coefficients for three phases:
   - Neutral → windup `[0, t_w]`: rest-to-rest (`a3 = -2*dq/dt³`, `a2 = 3*dq/dt²`)
   - Windup → release `[t_w, t_r]`: reaches `qd_release` (`a3 = (qd_r*Δ - 2*dq)/Δ³`, `a2 = (3*dq - qd_r*Δ)/Δ²`)
   - Release → rest `[t_r, T]`: decelerates from `qd_release` (`a3 = (2*(q_s-q_e) + qd_s*Δ)/Δ³`, `a2 = (-qd_s - 3*a3*Δ²)/(2*Δ)`)

**`step(q_target, qd_target)`:** `setJointMotorControlArray` POSITION_CONTROL with `positionGains=2.0` (gain=2.0 found to give best tracking at ~7% EE velocity error).

**`release_ball(ball_id, set_vel=None, dv_noise=None)`:** Removes grip constraint, then calls `resetBaseVelocity`. If `set_vel` is provided, uses that as the base velocity (used by `PyBulletThrowingSystem` to set `v_cmd` directly). If None, reads actual EE velocity. Adds `dv_noise` on top. Zeroes angular velocity (clears constraint-induced spin).

**`attach_ball(ball_id)`:** Creates `JOINT_FIXED` constraint between EE link and ball. Offset computed from current EE position to ball position at creation time.

**`ee_state()`:** `getLinkState(computeLinkVelocity=1)` → returns world-frame (pos, lin_vel, orient, ang_vel).

**Bug found and fixed during implementation:** `p.calculateJacobian` returns 2 values (linear, angular), not 3. Initial code unpacked 3 → fixed to unpack 2.

#### robot_arm/noise_models.py — noise classes

**`ArmNoise` (base):** Zero-noise identity. Defines interface:
- `pybullet_release_vel(v_cmd, ee_vel) -> (3,)` — velocity to set on ball at release in PyBullet. Different noise types return different things: VelocitySlipNoise perturbs v_cmd; ReleaseTimingJitter returns ee_vel directly (arm mid-decel).
- `perturb_numpy(v3d_np, n) -> (scale [n], additive [n,3])` — for MC batch in apply_policy. `v3d_actual = scale * v3d + additive`. Scale < 1 for slip/jitter; additive = N(0,σ²) for bias/slip.
- `sample_release_offset() -> int` — extra PyBullet steps before releasing (timing jitter only).

**`VelocityBiasNoise(sigma)`:** `dv ~ N(0, sigma²·I₃)`. `perturb_numpy` returns `(ones, N(0,σ²))`. **Note: this is UNLEARNABLE.** For zero-mean symmetric noise, the optimal noise-aware policy is mathematically identical to the noiseless policy. Adding it to apply_policy does not change what speed the policy learns — only how confidently it believes it will land (honest vs optimistic cost). Kept for baseline comparison only.

**`VelocitySlipNoise(alpha, sigma)`** *(added in noise redesign)*: `v_actual = (1-alpha)*v_cmd + N(0,sigma²)`. `perturb_numpy` returns `((1-alpha)*ones, N(0,sigma²))`. Learnable: the fractional loss grows with throw speed, so the policy must learn a consistent multiplier `1/(1-alpha)` across all target distances.

**`ReleaseTimingJitter(a, b, decel_rate, dt)`** *(redesigned)*: `t_d ~ U(a, b)`, `a > 0`. PyBullet: releases at delayed step, returns `ee_vel` (arm mid-deceleration — physically accurate). apply_policy: `scale = 1 - decel_rate * t_d / ||v_cmd||`. Learnable: mean delay `(a+b)/2 > 0` creates a systematic undershoot the policy must compensate for. Matches paper §5 model.

#### simulation_class/model_pybullet.py — `PyBulletThrowingSystem`

Drop-in replacement for `ThrowingSystem`. Same constructor parameters (mass, radius, launch_angle_deg, wind), same `rollout(s0, policy, T, dt, noise)` signature, same `(noisy_states, inputs, clean_states)` return format, same 8-D state layout `[x,y,z, vx,vy,vz, Px,Py]`. Exposes `launch_angle` attribute (required by `MC_PILOT.apply_policy`).

**Per-rollout sequence:**
1. `p.connect(p.DIRECT)` — fresh client each rollout (training); swap to `p.GUI` for demo.
2. Load ground plane, arm URDF. Create `ArmController`, call `reset()`.
3. Create ball sphere (m=0.0577, r=0.0327), set `linearDamping=0, angularDamping=0`.
4. `arm.attach_ball(ball_id)`.
5. Call `policy(s0, t=0)` → scalar speed. Convert to `v_cmd` via `_speed_to_velocity` (same azimuth/elevation math as numpy sim).
6. `arm.plan_throw(v_cmd, release_pos, t_w, t_r, T_arm)`.
7. Step PyBullet at dt Hz. During arm phase: command joint setpoints. At release step (+ timing jitter offset from `arm_noise.sample_release_offset()`): call `arm_noise.pybullet_release_vel(v_cmd, ee_vel)` to decide what velocity to set:
   - No noise / VelocityBiasNoise / VelocitySlipNoise: perturbs v_cmd → `p.resetBaseVelocity` to that value
   - ReleaseTimingJitter: returns `ee_vel` (actual arm velocity at the delayed step, physically accurate)
8. After release: each step, compute `_ball_accel(pos, vel, mass, radius, wind)` from model.py, subtract gravity component, apply remaining drag force via `p.applyExternalForce`. Same Eq. 35 physics as the numpy sim.
9. Landing detection: `pos[2] <= ball_radius + 0.005`. Linear interpolation to exact z=0 crossing (matches numpy sim).
10. `p.disconnect()`. Return trajectory arrays.

**Original design (set_vel=v_cmd always):** During testing, position-control tracking gave ~90% velocity accuracy at best. Setting to `v_cmd` directly decoupled ball physics from arm-tracking quality and gave a clean match with apply_policy. This design was retained for VelocityBiasNoise and VelocitySlipNoise.

**Updated design for ReleaseTimingJitter:** The physical story requires using the actual arm EE velocity at the delayed time (arm is decelerating). For this noise class, `pybullet_release_vel` returns `ee_vel` — the ball gets whatever velocity the arm has at that moment. The apply_policy approximation (`scale = 1 - decel_rate * t_d / ||v_cmd||`) must match this behaviour closely enough for the GP to be accurate.

**Landing detection bug found and fixed:** Initial code used `pos[2] <= 0.0` but ball center stops at `z ≈ ball_radius` on the ground plane. Ball was bouncing/rolling and the loop ran all remaining steps, giving landing x ≈ 3.23m (wrong). Fixed to `pos[2] <= ball_radius + 0.005`.

**Rollout speed:** ~0.1s per rollout in DIRECT mode. 20 rollouts per seed = ~2s overhead vs numpy sim.

#### policy_learning/MC_PILCO.py — two edits to `MC_PILOT`

**Edit 1 — `__init__` signature:** Added `arm_noise=None` kwarg, stored as `self.arm_noise`. When `None`, class behaves identically to original (zero regression for the parity test).

**Edit 2 — `apply_policy` body (updated in noise redesign):** After `v3d = torch.cat([vx, vy, vz], dim=1)`, the perturbation now uses the `perturb_numpy` interface:
```python
if self.arm_noise is not None:
    v3d_np = v3d.detach().cpu().numpy()
    scale_np, additive_np = self.arm_noise.perturb_numpy(v3d_np, num_particles)
    scale    = torch.tensor(scale_np[:, None], ...)   # [M, 1] detached
    additive = torch.tensor(additive_np, ...)          # [M, 3] detached
    v3d = scale * v3d + additive
```
`scale` and `additive` are constants w.r.t. policy parameters (detached). Gradient path is preserved: `cost ← GP_positions ← v3d ← speed ← policy_params`. The `scale * v3d` form (vs old `v3d + dv`) allows multiplicative noise (VelocitySlipNoise, ReleaseTimingJitter) to reduce gradient magnitude by the correct factor, so the policy learns to increase speed proportionally.

**Verified:** Running `test_mc_pilot.py -seed 1 -num_trials 1` (numpy sim, `arm_noise=None`) after both edits gives the same `Final trial cost: 0.0093` as before — zero regression.

#### policy_learning/Policy.py

Copied from `mc-pilot-elevated/policy_learning/Policy.py` (which has `Stratified_Throwing_Exploration`). The `mc-pilot/` version only had `Baseline_Throwing_Exploration`. This was discovered during integration testing: `AttributeError: module 'policy_learning.Policy' has no attribute 'Stratified_Throwing_Exploration'`.

#### standalone_throw.py

Standalone visual/mechanical test. No MC-PILOT, no GP. Loads iiwa7 in `p.GUI` (or `p.DIRECT` with `--direct`), plans a throw at hardcoded `v_cmd` toward a target, executes the arm trajectory, releases ball, renders trajectory trace. CLI: `--speed`, `--target_dist`, `--direct`.

**Note on expected error:** The `--speed` and `--target_dist` args are NOT matched to each other — the script demonstrates mechanical correctness of the arm and ball physics, not targeting accuracy. At `--speed 2.0 --target_dist 0.75`, the ball overshoots to ~1.17m (expected: 2.0 m/s from z=0.5m sends ball ~0.67m in x from release, which is at x=0.5m → landing x≈1.17m). The RL in `test_mc_pilot_pb_A.py` learns the correct speed for each target distance.

#### test_mc_pilot_pb_A.py — zero-noise PyBullet baseline

Same structure as `test_mc_pilot_e_strat5.py`. Uses `PyBulletThrowingSystem(arm_noise=None)` and `MC_PILOT(arm_noise=None)`. Success criterion: hit rate ≥ 4/5 within 5 trials (parity with mc-pilot Config A).

#### test_mc_pilot_pb_A_noisy.py — VelocityBiasNoise demo (unlearnable baseline)

Uses `VelocityBiasNoise(sigma)` passed to both `PyBulletThrowingSystem` and `MC_PILOT`. CLI arg `-noise_aware 1` (default) passes the shared instance to MC_PILOT; `-noise_aware 0` passes `None` to MC_PILOT only. **Note:** subsequent analysis showed this noise type is unlearnable (zero-mean, symmetric) — noise-aware and naive policies converge to the same aim. Use PB-B or PB-C for a scientifically meaningful noise-aware vs naive comparison.

#### test_mc_pilot_pb_B.py — VelocitySlipNoise demo (learnable, Option B)

Uses `VelocitySlipNoise(alpha, sigma)`. `v_actual = (1-alpha)*v_cmd + N(0,sigma²)`. Learnable because the fractional velocity loss scales with throw speed. Results directory: `results_mc_pilot_pb_B/alpha_{alpha}_{aware|naive}/{seed}/`. Added after paper analysis showed VelocityBiasNoise is not demonstrably learnable.

#### test_mc_pilot_pb_C.py — ReleaseTimingJitter demo (learnable, Option C, paper-faithful)

Uses `ReleaseTimingJitter(a, b, decel_rate)`. Gripper delay `t_d ~ U(a,b)`, `a>0`. PyBullet uses same `(1 - decel_rate*t_d/||v_cmd||)*v_cmd` formula as apply_policy (not actual arm EE velocity — see PB-C fix above). Results directory: `results_mc_pilot_pb_C/delay_{a}_{b}_{aware|naive}/{seed}/`. Parallel-safe with all other scripts.

#### demo_pybullet_gui.py

Loads trained policy from `results_*/seed/log.pkl` (reads `parameters_trial_list[-1]` which is an `OrderedDict` of `{log_lengthscales, centers, f_linear.weight}`). Spawns `p.GUI`, executes N throws, renders: arm motion, ball trajectory trace (`addUserDebugLine`), target marker (red sphere), landing marker (green=hit, orange=miss) + error text. Optional `--record output.mp4` via `startStateLogging(STATE_LOGGING_VIDEO_MP4)`. `--slow N` multiplies `time.sleep(dt)` for slower playback.

---

### Parameter derivation for Config PB-A

**Velocity reachability:** KUKA iiwa7 joint velocity limits `[1.71, 1.71, 1.75, 2.27, 2.44, 3.14, 3.14]` rad/s. Heuristic peak EE speed for multi-joint coordination: ~2.5 m/s. Paper's `uM=3.5` is unreachable. Retargeted to `uM=2.5`.

**Speed-to-range mapping** (initial estimate from numpy sim; later re-verified in PyBullet — see calibration bug below):
| Speed (m/s) | Numpy range (m) | PyBullet range (m) |
|-------------|-----------------|-------------------|
| 1.4 | 0.470 | **0.580** |
| 1.5 | 0.512 | 0.624 |
| 2.0 | 0.744 | 0.867 |
| 2.3 | 0.899 | 1.027 |
| 2.5 | 1.009 | **1.142** |

→ The numpy and PyBullet sims give different ranges. PyBullet Eq. 35 drag is applied via `applyExternalForce` each step; the numpy sim uses a different drag implementation. The calibration bug section below gives the corrected values.

**lengthscales:** Target range = lM − lm = 0.5m. Applying E-Strat5 rule: `ls = 0.15 × 0.5 = 0.075` → rounded to `[0.08, 0.08]`. At this scale, sensitivity between lm and lM = `exp(−0.5*(0.5/0.08)²) ≈ 0` — targets are fully distinguishable by the RBF policy.

**IK feasibility** (verified): `p.calculateInverseKinematics` to `[0, 0, 0.5]` gives EE error 0.024m — within acceptable tolerance. IK to `[0.5, 0, 0.5]` gives error 0.020m.

| Parameter | Value | Note |
|-----------|-------|-------|
| `uM` | 2.5 m/s | iiwa7 EE limit |
| `uMin` | 1.4 m/s | Exploration floor; 1.4→0.58m gives GP coverage below lm=0.6 |
| `lm` | ~~0.5~~ **0.6 m** | Corrected after calibration (0.5m unreachable with uMin=1.4) |
| `lM` | ~~1.0~~ **1.1 m** | Corrected; 1.1m requires v≈2.45 m/s, within uM=2.5 |
| `T` | 0.60 s | Ball lands ~0.52s at uM; margin added |
| `lc` | 0.5 m | Same as Config A |
| `Nexp` | 5 | 5 strata over [1.4, 2.5] = bands of 0.22 m/s |
| `lengthscales_init` | [0.08, 0.08] | E-Strat5 rule: 0.15 × 0.5m |
| `RELEASE_POS` | [0, 0, 0.5] | IK places EE at ≈(0.024, 0, 0.495) |

---

### Speed-to-range calibration bug (found after first noisy runs)

**Problem:** Parameter choices for `lm`, `lM`, `uMin` were based on estimates that did not match actual PyBullet physics.

**Actual PyBullet calibration** (DIRECT mode, z=0.5m release, 35° launch angle, no drag override errors):

| Speed (m/s) | Range (m) |
|-------------|-----------|
| 1.20 | 0.494 |
| 1.40 | **0.580** ← assumed ≈0.47 (was wrong) |
| 1.50 | 0.624 |
| 1.60 | 0.670 |
| 1.70 | 0.718 |
| 1.80 | 0.766 |
| 1.90 | 0.816 |
| 2.00 | 0.867 |
| 2.10 | 0.919 |
| 2.20 | 0.973 |
| 2.30 | 1.027 |
| 2.40 | 1.083 |
| 2.50 | **1.142** ← assumed ≈1.009 (was wrong) |

**Consequence:** With `uMin=1.4, lm=0.5`, targets in [0.5, 0.58]m were physically unreachable — the minimum commandable speed (1.4 m/s) already lands at 0.58m. The policy cannot output low enough speeds to hit near targets because the GP has no training data below 1.4 m/s. This caused systematic overshoot of close targets and explains why CTRL2 (target=0.519m, policy_speed=1.491 → landed at 0.601m, err=10.8cm) missed despite the noise making the release *slower* than commanded.

**Fix:** Adjusted `lm=0.6, lM=1.1`. At these boundaries:
- lm=0.6m requires speed ≈1.47 m/s — above uMin=1.4 but the GP still has coverage below lm from exploration
- lM=1.1m requires speed ≈2.45 m/s — within uM=2.5

Files changed: `test_mc_pilot_pb_A.py`, `test_mc_pilot_pb_A_noisy.py` — both have `lm`, `lM`, and surrounding comments updated.

---

### Results

**First noisy runs (seed=1, 10 trials, sigma=0.15, OLD lm=0.5/lM=1.0 — SUPERSEDED by calibration fix above):**

| Config | Final cost | Hit rate (<10cm) | Hit rate (<15cm) | Mean error |
|--------|-----------|-----------------|-----------------|------------|
| noise-aware | ~0.043 | 2/10 | 5/10 | 14.7 cm |
| naive | ~0.0004 | 2/10 | 5/10 | 15.0 cm |

**Interpretation of first runs:**
- Hit rate was low primarily because the speed-to-range calibration was wrong (not the noise)
- Noise-aware cost staying at ~0.04 is correct behaviour: it honestly accounts for sigma=0.15 velocity scatter which produces ~10-15cm landing spread; the cost cannot fall below the noise floor
- Naive cost reaching ~0.0003 is falsely optimistic: apply_policy runs noiseless particles so the GP predicts clean landings, but actual deployment has noise
- Both strategies converge to the same real-world performance because N(0,σ²) zero-mean noise does not bias the optimal aim point; for biased noise the strategies would differ

**Zero-noise run (seed=1, 10 trials, OLD lm=0.5/lM=1.0):** Final cost ≈0.0003 (user-observed). Results file overwritten by an accidental background re-run — not recoverable. Key result: zero-noise PyBullet sim converges to near-zero cost, validating the GP+physics pipeline.

**Corrected runs (lm=0.6, lM=1.1): pending — scripts updated, user will rerun.**

---

### Paper noise model analysis (led to noise redesign)

After first noisy runs showed poor hit rate and both noise-aware and naive performing identically, we re-examined the theoretical basis and read the actual paper.

**Key insight — VelocityBiasNoise is unlearnable:**
For zero-mean symmetric noise (`dv ~ N(0, σ²I)`), the optimal policy satisfies:
- `∂J/∂v = E[∂cost/∂landing | v] = 0` at the same `v` as the noiseless optimum
- The noise adds variance but does not shift the mean landing position
- Therefore, the noise-aware policy is mathematically identical to the noiseless policy for any zero-mean noise
- The only difference between noise-aware and naive is cost calibration (honest vs falsely optimistic uncertainty accounting), not actual throw aim
- This means our `test_mc_pilot_pb_A_noisy.py` could not demonstrate that RL improves with noise awareness — both policies aim identically

**Paper analysis (Turcato et al. 2025, §5 — Delay Distribution Optimization):**
- The paper does NOT add velocity noise. The noise source is **gripper opening delay**: `t̃_r = t_{r_cmd} + t_d`, where `t_d ~ U(a, b)`, `a > 0`.
- Because the arm is decelerating after the nominal release time `t_r`, releasing late means the ball gets a lower-than-commanded velocity. The shortfall scales with throw speed (higher v_cmd → more deceleration during delay → bigger velocity loss).
- This IS learnable: the policy must output a higher speed to compensate the mean delay `(a+b)/2`, and the compensation grows with target distance.
- Additionally, the paper fits (a, b) from data using Bayesian Optimization, and shifts `t_{r_cmd} = t_r - â` to pre-compensate the mean delay. Our simulation version learns the speed correction through the RL loop instead.

### Noise model redesign: VelocitySlipNoise (B) + ReleaseTimingJitter (C) added

**Problem with VelocityBiasNoise:** Zero-mean Gaussian noise is provably unlearnable. For symmetric noise, the optimal noise-aware policy is mathematically identical to the noiseless policy — the policy cannot improve its aim by knowing about the noise. This undermines the RL demo: there is no demonstrable advantage of the noise-aware strategy.

**Paper analysis (Turcato et al. 2025, §5):** The paper uses release timing jitter `t_d ~ U(a, b)` with `a > 0` — a systematic minimum delay. The arm decelerates during the delay, so actual release velocity is less than commanded. The loss scales with throw speed (higher v → arm decelerates faster → bigger undershoot). This IS learnable: the policy must output higher speeds to compensate.

**Changes:**

**`robot_arm/noise_models.py` — full redesign:**
- `ArmNoise` base class: added `pybullet_release_vel(v_cmd, ee_vel)` and `perturb_numpy(v3d_np, n) -> (scale, additive)` interface methods. The `(scale, additive)` decomposition allows gradient to flow through `v3d` in apply_policy: `v3d_actual = scale * v3d + additive`.
- `VelocityBiasNoise`: updated to use new interface. `perturb_numpy` returns `(ones, N(0,σ²))` — equivalent to old additive-only behaviour.
- `VelocitySlipNoise` **(new, Option B):** `v_actual = (1-α)*v_cmd + N(0,σ²)`. Learnable because the fractional loss grows with throw distance. Policy must learn to multiply all speeds by `1/(1-α)`. Naive policy systematically undershoots, more so at longer ranges. Default: `alpha=0.12, sigma=0.04`.
- `ReleaseTimingJitter` **(redesigned, Option C; pybullet_release_vel fixed after first run):** `t_d ~ U(a, b)` with `a > 0` (default: a=0.02, b=0.07). `sample_release_offset()` samples and saves `_last_t_d`. In PyBullet: `pybullet_release_vel` applies `v_cmd * (1 - decel_rate * _last_t_d / ||v_cmd||)` — same formula as apply_policy, so simulator and particle model are consistent. (Original design returned `ee_vel` but PyBullet position control gives chaotic, uncalibrated EE velocities — this was the root cause of PB-C failure.) Mean loss ≈ `decel_rate * (a+b)/2` m/s.

**`simulation_class/model_pybullet.py`:**
- Release block now calls `arm_noise.pybullet_release_vel(v_cmd, ee_vel)` and sets ball velocity to the result via `p.resetBaseVelocity`.
- For `VelocitySlipNoise`: ball gets `(1-α)*v_cmd + noise`.
- For `ReleaseTimingJitter`: ball gets actual `ee_vel` at the delayed timestep (arm is mid-deceleration — physically accurate).
- For no noise: ball gets `v_cmd` exactly (unchanged behaviour).

**`policy_learning/MC_PILCO.py` — `apply_policy`:**
- Replaced `sample_initial_velocity_noise` with `perturb_numpy(v3d_np, n)` → `(scale, additive)`.
- `v3d = scale * v3d + additive` — gradient flows through v3d for all noise types.

**New test scripts:**
- `test_mc_pilot_pb_B.py`: `VelocitySlipNoise(alpha, sigma)`. CLI: `-alpha`, `-sigma`, `-noise_aware`.
- `test_mc_pilot_pb_C.py`: `ReleaseTimingJitter(a, b, decel_rate)`. CLI: `-a`, `-b`, `-decel_rate`, `-noise_aware`. Prints mean delay and expected mean velocity loss at startup.

---

### PB-B/C Run 1: α=0.12, uM=2.5 — two bugs found, both fixed

**Results (seed=1, 10 trials):**

| Config | Aware hits | Naive hits |
|--------|-----------|-----------|
| PB-B α=0.12, uM=2.5 | 7/15 | 10/15 (naive WON — wrong) |
| PB-C a=0.02,b=0.07, uM=2.5 | 1/15 | 1/15 (both failed) |

**Bug 1 — PB-C: model-reality mismatch in `pybullet_release_vel` (FIXED):**
`ReleaseTimingJitter.pybullet_release_vel` returned the arm's actual EE velocity (`ee_vel`), but PyBullet position control doesn't track well: joint limits cap achievable EE speed at ~0.58 m/s for v_cmd=2.0 m/s, and oscillations cause actual EE velocity to range 0.1–6.6 m/s through the motion. Ball got near-random velocities → GP training data chaotic → RL couldn't learn. **Fix:** `pybullet_release_vel` now applies the same formula as `perturb_numpy` (`v_cmd * (1 - decel_rate * t_d / ||v_cmd||)`) using the `_last_t_d` saved by `sample_release_offset`. PyBullet and apply_policy now use identical noise distributions.

**Bug 2 — PB-B/C: reachability cap (FIXED by increasing uM):**
With α=0.12 and uM=2.5, the aware policy needs `v_cmd = v_needed / 0.88`. For lM=1.1m (v_needed≈2.45 m/s), this requires v_cmd=2.78 m/s > uM=2.5 — unreachable. Max achievable range with slip = f(2.5×0.88) = f(2.2) = 0.97m. ~25% of targets (0.97–1.1m) were unreachable for the aware policy, capping hit rate at ~75%.

**Bug 3 — PB-B: insufficient slip for clear separation (FIXED by increasing α):**
With α=0.12, naive undershoots by only 6–10 cm for close targets — within the 10 cm hit threshold. Naive expected to hit ~30% of targets on physics alone, making aware vs naive difference unclear. Additionally, the two runs sample `arm_noise.rng` at different rates (aware advances it 600k times per trial during optimization; naive does not), so actual throw noise sequences differ between runs — confounding the comparison.

**Fixes applied (current defaults):**

| Script | Parameter | Old | New | Reason |
|--------|-----------|-----|-----|--------|
| PB-B | `alpha` | 0.12 | **0.20** | Naive misses all targets (errors 0.11–0.25m > 0.1m) |
| PB-B | `uM` | 2.5 | **3.0** | Max aware range = f(0.80×3.0) = f(2.4) = 1.083m, covers [0.6,1.1m] |
| PB-C | `a` | 0.02 | **0.04** | Mean loss = 4.0×0.08 = 0.32 m/s; naive misses all targets |
| PB-C | `b` | 0.07 | **0.12** | Same reason; also larger jitter variance for more realistic noise |
| PB-C | `uM` | 2.5 | **3.0** | For lM=1.1m: v_cmd = 2.45+0.32 = 2.77 m/s < 3.0, all targets reachable |

**Expected results after fixes:**
- Aware: ~90–100% hits (all targets reachable, compensation is a single learnable multiplier/offset)
- Naive: ~0% hits (systematic undershoot 0.11–0.25m for B; 0.13–0.25m for C)

Note: ball velocity is set explicitly via `resetBaseVelocity` and is NOT limited by arm tracking quality, so uM=3.0 is safe regardless of arm joint velocity limits.

---

### PB-B Run 2: α=0.20, uM=3.0 — results

**Run:** seed=1, num_trials=10, alpha=0.20, sigma=0.04, uM=3.0

| Config | Total hits (15 throws) | Policy-only hits (10 throws) | Mean error | Final opt cost |
|--------|------------------------|------------------------------|------------|----------------|
| Aware  | 8/15 (53%)             | 5/10 (50%)                   | 0.100 m    | ~0.009         |
| Naive  | 4/15 (27%)             | 1/10 (10%)                   | 0.125 m    | ~0.001         |

Per-throw errors (throws 1–15; first 5 are exploration, identical for both):

| Throw | Aware error (m) | Naive error (m) | Note |
|-------|-----------------|-----------------|------|
| 1  | 0.217 | 0.217 | exploration |
| 2  | 0.082 | 0.082 | exploration |
| 3  | 0.097 | 0.097 | exploration |
| 4  | 0.216 | 0.216 | exploration |
| 5  | 0.030 | 0.030 | exploration |
| 6  | 0.094 ✓ | 0.129 ✗ | |
| 7  | 0.039 ✓ | 0.151 ✗ | |
| 8  | 0.124 ✗ | 0.135 ✗ | |
| 9  | 0.084 ✓ | 0.153 ✗ | |
| 10 | 0.106 ✗ | 0.090 ✓ | |
| 11 | 0.103 ✗ | 0.107 ✗ | |
| 12 | 0.033 ✓ | 0.106 ✗ | |
| 13 | 0.106 ✗ | 0.101 ✗ | |
| 14 | 0.118 ✗ | 0.141 ✗ | |
| 15 | 0.055 ✓ | 0.127 ✗ | |

**Interpretation:**

Direction is correct — aware outperforms naive (50% vs 10% on policy trials; 53% vs 27% overall). The fix worked.

The aware policy did not reach the expected ~90–100% for one structural reason: the additive σ=0.04 m/s noise creates irreducible per-throw scatter that cannot be compensated by policy speed adjustment. The policy correctly learns to multiply commanded speeds by ~1.25 (= 1/(1-0.20)) to compensate the systematic slip. But σ=0.04 per component still adds ~2–4 cm of random landing scatter per throw. Looking at the aware near-misses (0.103, 0.106, 0.106, 0.118, 0.124), they are all within 2–3 cm of the 10 cm threshold — the policy is landing on-target but the stochastic noise pushes ~50% of throws just outside the circle.

The naive policy cost (~0.001) is falsely optimistic: apply_policy runs 400 particles with no noise, so the GP predicts perfect landings. Actual deployment has 20% slip → systematic undershoot of 0.09–0.15 m. The aware cost (~0.009) is higher and honest: particles include the slip, so the cost correctly reflects that even with compensation, stochastic noise prevents zero-cost landings.

**Summary:** The RL learns the correct compensation (aware > naive by factor of 5× on policy trials), confirming that speed-dependent velocity loss is learnable. The 50% ceiling is a noise floor from σ=0.04 additive scatter, not a failure of learning.

---

### PB-B Run 3: σ=0, Nexp=10 — GP degeneration experiment (negative result)

**Run:** seed=1, num_trials=10, alpha=0.20, sigma=0.00, Nexp=10, uM=3.0

Motivation: remove the additive noise to isolate the pure 20% multiplicative slip. Expected: aware ~100% (perfectly learnable with no randomness), naive ~0% (systematic undershoot).

| Config | Total hits (20 throws) | Policy-only hits (10 throws) | Mean error | Final opt cost |
|--------|------------------------|------------------------------|------------|----------------|
| Aware  | 7/20 (35%)             | 6/10 (60%)                   | 0.145 m    | ~0.005–0.012   |
| Naive  | 6/20 (30%)             | 5/10 (50%)                   | 0.161 m    | ~0.0005        |

**Result:** Separation essentially collapsed (60% vs 50%) — much worse than the σ=0.04 run (50% vs 10%). Naive performed far better than expected.

**Root cause — GP lengthscale explosion:**

With σ=0, the 10 exploration throws produce perfectly clean, noiseless ballistic trajectories. The GP hyperparameter optimizer (MLE) found that the mathematically easiest fit is a nearly-flat function with enormous lengthscales: **1791 m, 1602 m, 357 m** for the three GPs (the domain is ~1 m in position, ~3 m/s in velocity).

A GP with lengthscale >> domain size is geometrically equivalent to drawing one flat horizontal line through all the data — it predicts the same landing position regardless of launch speed. The GP cannot distinguish "ball thrown at 1.5 m/s" from "ball thrown at 2.5 m/s."

With σ=0.04, the additive noise forces the GP to find a finite lengthscale that explains *why* throws with similar speeds land at different positions. That structure is what allows the aware policy to learn the 1/(1-α) multiplier. Without it, both aware and naive optimize against a constant predictor and converge to similar speeds.

**Key insight:** Additive noise (σ=0.04) is not just a noise source for the aware/naive comparison — it is necessary GP regularization. Without it, MLE collapses to a degenerate solution.

**Change also made this run:** Nexp increased from 5 to 10 (user decision). With Nexp=10, the first policy trial is labeled "TRIAL 9" (the code uses `first_trial_index = num_explorations - 1` as the global index). Explorations run silently in ~1s total (PyBullet DIRECT mode, ~0.1s per rollout, no verbose output per throw — data is collected correctly).

**Conclusion:** σ=0.04 is the correct default for PB-B. The sigma=0 result is documented as a failed experiment.

---

## Baseline Bugs Fixed

### Documentation Update: Mentor meeting crash brief (LaTeX)
- **Files:** `mentor_meeting_brief.tex`, `change_history.md`
- **Problem:** A complete but concise handover was needed for mentor discussion so a teammate with no prior participation can answer technical and implementation-level questions confidently.
- **Change:** Added a compact LaTeX briefing that covers architecture, code map, algorithm flow, key equations, critical failure modes and fixes, result summary across configs, scope limitations, rapid Q&A, and runnable commands, including real code snippets and pseudocode.
- **Result:** The repository now has a ready-to-compile mentor prep document with high-density technical coverage for defense-style questioning.

### Documentation Update: Repository-verified Graphify map and file crosswalk
- **Files:** `graphify-out/graph.html`, `graphify-out/graph.json`, `graphify-out/GRAPH_REPORT.md`, `change_history.md`
- **Problem:** The previous Graphify architecture view reflected an idealized four-folder layout from the report, but this checkout currently contains `mc-pilot/` and `mc-pilot-elevated/` as primary project folders, with pybullet-related scripts located inside `mc-pilot/`. This made it hard to trace report claims to concrete files.
- **Change:** Rebuilt Graphify outputs to be repo-verified, explicitly marking which sub-project folders/files are present vs report-mentioned-only in this branch, and added a detailed file-level crosswalk for sub-project mapping, failure-mode fix locations, shared core modules, stratified exploration implementation, and wind-state augmentation status.
- **Result:** The Graphify artifacts now provide an accurate, auditable bridge from report architecture to real code locations in the current repository snapshot.

### Documentation Update: Graphify layered architecture diagram refreshed
- **Files:** `graphify-out/graph.html`, `graphify-out/graph.json`, `graphify-out/GRAPH_REPORT.md`, `change_history.md`
- **Problem:** The previous Graphify visualization mixed low-level extracted entities and did not clearly present the exact four-subproject architecture, inheritance arrows, shared core files, and wind cross-cutting scope requested for repository communication.
- **Change:** Replaced Graphify outputs with a curated layered architecture view showing: `mc-pilot/` as the base, `mc-pilot-elevated/` and `mc-pilot-pybullet/` as layer-2 extensions, `mc-pilot-pb-elevated/` as the layer-3 combined branch, plus explicit `shared_across` and wind `modifies` links to all four.
- **Result:** The Graphify artifacts now communicate the repository structure and dependency relationships directly and unambiguously.

### Documentation Update: Added report defense checklist
- **Files:** `report_defense_checklist.md`, `change_history.md`
- **Problem:** The project had detailed implementation notes and experiment logs, but no defense-focused document explaining how to present the work strongly while staying accurate about scope, contributions, and limitations.
- **Change:** Added a dedicated checklist covering what can be claimed confidently, what should not be overclaimed, how to present the release-height extension truthfully, likely defense questions, and the main limitations to admit early.
- **Result:** The repo now includes a ready-to-use defense guide that helps present the project as impressive, rigorous, and honest.

### Fix 1: T_control passed as steps instead of seconds
- **File:** `test_mc_pilot.py`
- **Problem:** `"T_control": T / Ts` (= 100) was passed. `reinforce_policy()` internally computes `control_horizon = int(T_control / T_sampling) = int(100 / 0.01) = 10,000` steps — nearly crashed the laptop.
- **Fix:** Changed to `"T_control": T` (= 1.0 seconds). Now `control_horizon = int(1.0/0.01) = 100`.

### Fix 2: opt_steps_list index out of range
- **File:** `test_mc_pilot.py`
- **Problem:** `trial_index` in `reinforce()` starts at `Nexp - 1 = 4`, but lists were sized `[Nopt] * num_trials`. Index 4 out of range for a 3-element list.
- **Fix:** Changed list sizes from `[Nopt] * num_trials` to `[Nopt] * (Nexp + num_trials)`.

### Fix 3: No gradient path to policy parameters
- **File:** `policy_learning/MC_PILCO.py` — `MC_PILOT.apply_policy()`
- **Problem:** `apply_policy()` passed policy speed as GP input. `data_to_gp_input()` strips all inputs, so gradient path from cost → policy params was broken. `RuntimeError: element 0 of tensors does not require grad`.
- **Fix:** Rewrote `apply_policy()` to:
  1. Call policy at t=0 to get scalar speed (with grad)
  2. Convert speed → 3D velocity via differentiable torch ops (atan2, cos, sin)
  3. Embed velocity into initial particle state dims 3:6
  4. GP propagates from that state, preserving gradient chain
- **Result:** `policy weight grad norm = 0.002853 > 0` confirmed.

---

## Performance Improvements

### Change 1: Particle landing freeze (critical)
- **File:** `policy_learning/MC_PILCO.py` — `MC_PILOT.apply_policy()`
- **Problem:** GP propagated particles for all 100 steps regardless of landing. After z≤0, GP kept predicting nonsense physics (ball underground). Cost at T=100 was garbage → cost stuck at ~0.998, no gradients.
- **Fix:** Added `landed` boolean mask. Once a particle's z≤0, its state is frozen (copied from previous step) for all remaining timesteps. Matches paper Section 4.2.2.
- **Result:** Cost dropped from 0.998 → 0.949 at step 0, and fell to 0.882 during optimization. Real learning confirmed.

### Change 2: Widened lc from 0.1 to 0.5m
- **File:** `test_mc_pilot.py`
- **Problem:** With `lc=0.1m`, cost saturates to ~1.0 for any landing error >0.15m. Early training errors are 0.3–1.5m, so gradients were near zero everywhere.
- **Fix:** Increased `lc` from 0.1 to 0.5m. With `lc=0.5`, meaningful gradient exists up to ~1m error.
- **Result:** Cost dropped to ~0.44 in first trial (from ~0.88 plateau with lc=0.1).

### Change 3: Relaxed early stopping
- **File:** `test_mc_pilot.py`
- **Problem:** Early stopping parameters from cartpole were too aggressive for noisy MC cost. Optimizer quit at ~600 steps (out of 1500) due to MC noise triggering the convergence criterion.
- **Fix:** `min_diff_cost` 0.08→0.02, `num_min_diff_cost` 200→400, `min_step` 200→400.
- **Result:** Optimizer now runs ~1200–1500 steps before stopping.

### Change 4: Reduced simulation horizon T from 1.0 to 0.7s
- **File:** `test_mc_pilot.py`
- **Reason:** Ball lands in ~0.58s at max speed (35° elevation, 0.5m release height). With T=1.0s, 42% of GP steps were wasted on frozen particles.
- **Fix:** Reduced T to 0.7s (35 steps at Ts=0.02).
- **Result:** ~30% speedup at no accuracy cost.

### Change 5: Increased timestep Ts from 0.01 to 0.02s
- **File:** `test_mc_pilot.py`
- **Reason:** Sequential Python loop over GP steps was the bottleneck. Halving loop iterations (100→35) gives ~2x speedup. Ball physics are smooth enough for 0.02s.
- **Result:** Time per 100 opt steps: 25s → 8–9s (~3x overall speedup combined with Change 4).

---

## Experiments That Did NOT Work

### Experiment A: Tighten lc to 0.2m (after 10 trials at lc=0.5)
- **Hypothesis:** Policy has converged to ~0.1m errors, tighten lc to sharpen accuracy.
- **Result:** FAILED. Cost jumped back to 0.73–0.81 (was 0.13–0.17). Most particles still land 0.3–0.5m from target in early optimization, which saturates at lc=0.2. Gradient starvation returned.
- **Lesson:** Don't tighten lc until the policy consistently achieves <0.2m errors across the full target range, not just on easy targets.

### Experiment B: Use baseline exploration policy (Eq. 13) instead of random
- **Hypothesis:** Baseline computes analytically correct speed per target (paper Algorithm 1 line 4). Throws near targets → better GP coverage for far-range targets.
- **Result:** FAILED. Hit rate dropped from 50% to 20%. The baseline throws were all near-optimal parabolas with very similar dynamics — the GP trained on 5 nearly-identical trajectories and overfitted to that narrow region. Random exploration provides diverse speeds covering a wider range of velocities and positions, which is better for GP model learning.
- **Lesson:** For the GP to generalize, exploration data needs diversity. Analytically correct ≠ informationally diverse.

### Experiment C: Increase torch threads
- **Hypothesis:** `torch.set_num_threads(1)` leaves CPU idle. Use all cores.
- **Result:** FAILED. Time per 100 steps went from 25s → 35s (40% slower). Thread overhead dominates for small [400×8] tensors. Reverted to 1 thread.

---

---

### Experiment G: Revert lc from 0.5 m to paper's 0.1 m
- **File:** `test_mc_pilot.py`
- **Hypothesis:** lc was widened to 0.5 because early errors (0.3–1.5m) saturated the cost at lc=0.1, killing gradients. That saturation was caused by physically unreachable targets (lM=2.4). With lM=1.75 (all targets reachable) and a well-trained GP, exploration throws should land much closer to targets — keeping cost below saturation at lc=0.1. Sharper cost function should enable finer accuracy and lower final cost.
- **Changes:** `lc = 0.5 → 0.1`
- **Result:** FAILED. 0/10 hits. Cost floor stuck at ~0.80–0.81 across all 10 trials (never below 0.79). Errors actually worsened after Trial 5 (0.7–0.86m), suggesting policy wandering rather than learning.
- **Root cause:** Exploration throws still land 0.27–1.09m from targets (random speed, GP untrained at that point). At lc=0.1, an error of 0.27m gives cost ≈ 0.999 — essentially saturated. Nearly all particles are at cost~1.0 before Trial 1 even begins, so gradients are near zero and the optimizer can only scratch down to ~0.80 before signal disappears. The GP needs several trials at lc=0.5 to become accurate enough that lc=0.1 is viable.
- **Lesson:** lc=0.1 requires the policy to already be near-accurate before it provides useful gradients. It cannot bootstrap from scratch with random exploration. lc=0.5 is necessary for initial learning.

---

### Experiment F: Revert RBF center and weight init to paper's Eq. 22 (with corrected lM=1.75)
- **File:** `test_mc_pilot.py`
- **Hypothesis:** Experiment D tried this with lM=2.4 and failed (0/10 hits) — dead zone (Px<0.65) wasted 27% of centers on unreachable targets, and impossible far targets created noisy gradients. With lM=1.75 (all targets reachable), the gradient landscape is clean. Wider init may improve boundary smoothness and prevent local minima.
- **Changes:**
  - Centers: `Px ∈ [lm·cos(gM), lM] → [0, lM]`, `Py ∈ [lm·sin(-gM), lM·sin(gM)] → [-lM·sin(gM), lM·sin(gM)]`
  - Weights: `[-uM/2, uM/2] → [-uM, uM]`
- **Note:** Dead zone (Px < ~0.65m) is still ~37% of Px range, but all sampled targets are now within physics reach so gradients are meaningful.
- **Result:** FAILED. 2/10 hits. Cost stuck at ~0.45–0.50 across all 10 trials (Trial 1: 0.73→0.49, Trials 2–10: plateau immediately at 0.45–0.50, never escaping). Same failure mode as Experiment D despite correct lM=1.75.
- **Root cause:** The target domain is strictly a sector between 0.75m and 1.75m. By starting centers at Px=0, ~37% of the 250 basis functions land in a dead zone where targets never spawn. These become "ghost centers" — never trained by any real throw, they output persistent random background noise that corrupts the RBF sum across the entire target arc. This leaves only ~160 centers to cover the actual target region, which isn't enough density to sculpt a smooth, accurate speed ramp. The optimizer gets stuck at cost ~0.44–0.53 because the policy landscape is too noisy and under-resolved to optimize through.
- **Sub-experiment F1 additionally had:** wide weights [-uM, uM] causing tanh saturation on top of the center problem.
- **Conclusion:** Paper's Eq. 22 center domain is designed for their geometry and cannot be ported directly. Centers must begin at the actual target boundary (~lm·cos(gM)≈0.65m), ensuring all 250 basis functions cover regions where targets actually appear.

---

### Experiment E: Reduce lM from 2.4 m to 1.75 m (paper's value)
- **File:** `test_mc_pilot.py`
- **Hypothesis:** Paper defines target domain as l ∈ [0.75, 1.75] m. At lM=2.4 m with uM=3.5 m/s and α=35°, far targets may be physically unreachable — policy penalized for impossible throws. Reverting to paper's lM should eliminate far-target misses.
- **Changes:** `lM = 2.4 → 1.75`. RBF centers upper bound auto-updates (uses `lM` variable).
- **Result:** SUCCESS. 5/5 hits (100%). Errors: 85mm, 33mm, 23mm, 17mm, 8mm. Cost converged from 0.74 → 0.009 in Trial 1, reaching 0.001 by Trial 5. Trial 5 hit early stopping at step 1204 — policy fully converged. Far-target misses eliminated entirely.

---

## Exploration 1: Variable Platform Height (Elevated Targets)

### Setup
- **Folder:** `mc-pilot-elevated/` — full copy of `mc-pilot/`, original untouched
- **Idea:** Robot platform is at different heights above ground. Only `RELEASE_POS[2]`, `lM`, and `T` change per config. All other parameters (policy, GP, cost, lm, gM, M, Nb, lc) are identical to Config A.
- **RBF centers auto-update** — code already uses `lM` as a variable.
- **Max ranges verified** by running `check_max_range.py` with ThrowingSystem at uM=3.5, α=35°.

| Config | z_release | Max range (with drag) | lM used | T |
|--------|-----------|----------------------|---------|---|
| A | 0.5m | 1.647m | 1.75m (validated) | 0.70s |
| B | 1.0m | 1.973m | 1.90m | 0.85s |
| C | 1.5m | 2.233m | 2.15m | 0.95s |
| D | 2.0m | 2.457m | 2.35m | 1.00s |
| E | 0.0m | 1.156m | 1.10m | 0.55s |

**Scripts:** `test_mc_pilot_b.py` through `test_mc_pilot_e.py`
**Results dirs:** `results_mc_pilot_{b,c,d,e}/{seed}/`

### Config B, seed=1 (random exploration): FAILED — 0/10 hits
- All trial throws landed at x≈1.90m (max range) regardless of target
- Cost stuck at 0.70–0.73 across all 10 trials, never dropping
- Root cause: seed=1 exploration drew very low speeds (throws landing at 0.245m, 0.408m). GP never saw high-speed dynamics. Policy found max-speed local minimum.

### Fix: Stratified Exploration — `Stratified_Throwing_Exploration`
- **File:** `policy_learning/Policy.py` — added `Stratified_Throwing_Exploration` class
- Divides [0, uM] into Nexp=5 equal bands [0–0.7, 0.7–1.4, 1.4–2.1, 2.1–2.8, 2.8–3.5 m/s]. Each exploration throw samples from the next band in order. GP guaranteed to see the full speed range regardless of seed.
- **Adopted as default for all elevated configs (B–E).**

### Config B, seed=2 (random exploration): SUCCESS — 10/10 hits
- Got lucky: exploration throw 4 landed 18mm from target, giving GP good near-range data
- Trial 1: cost 0.882 → 0.005. Fully converged by Trial 3 (cost <0.001)
- Mean error: 20mm, min: 16mm
- Confirms z=1.0m is learnable when GP has good speed coverage

### Config B-Strat, seed=1 (stratified exploration): SUCCESS — 10/10 hits
- Same seed that failed completely with random exploration
- Trial 1: cost 0.811 → 0.003. Fully converged by Trial 3
- Mean error: 20mm, min: 6mm
- **Proves stratified exploration is seed-independent and robust**
- Lesson: random exploration is fragile at elevated heights because the speed-to-range mapping is less forgiving. Stratified is the reliable default.

### Config C-Strat, seed=1 (stratified, z=1.5m): SUCCESS — 10/10 hits
- Exploration errors: 0.17–1.56m (good spread across all speeds)
- Trial 1: cost 0.809 → 0.085. Fully converged by Trial 2 (cost 0.0005 by Trial 3)
- Errors (Trials 1–10): 16, 5, 12, 22, 27, 7, 11, 11, 24, 8 mm. Min: 5mm, max: 27mm.
- Target distances ranged from 0.75m to 2.06m — policy generalises across full arc
- Clean convergence: cost drops from 0.08 (T2) to 0.0005 by T3 and stays there

### Config D-Strat, seed=1 (stratified, z=2.0m): SUCCESS — 10/10 hits
- Exploration errors: 0.15–0.86m
- Trial 1: cost 0.827 → 0.024 (faster first-trial drop than C; better GP from z=2.0m longer flight)
- Errors (Trials 1–10): 7, 19, 15, 25, 21, 12, 18, 9, 29, 9 mm. Min: 7mm, max: 29mm.
- Target distances ranged from 0.82m to 2.20m — covers nearly the full lM=2.35m range
- Best first-trial convergence of all elevated configs (0.827 → 0.024 in one pass)

### Experiment H: Config E-Strat, seed=1 (stratified [0, uM], z=0.0m): FAILED — 0/10 hits
- Cost stuck at ~0.25 throughout all 10 trials (Trial 1: 0.663→0.172; Trials 2–10: plateaus immediately at 0.23–0.28, barely moving)
- Errors: 105–396mm, all well above 100mm threshold. Policy not converging at all.
- **Root cause: speed-range compression at z=0.0m.** From z=0.0 at α=35°, targets [0.75, 1.10]m require release speeds [~2.80, ~3.39] m/s (only 17% of [0, 3.5] m/s). With standard stratified exploration (5 equal bands of 0.7 m/s), throws from bands 1–4 land at x<0.75m and fall outside the target zone entirely. Only band 5 ([2.8, 3.5]) produces throws that reach the target. GP trained on 4 irrelevant short-range throws and only 1 useful throw — far too little data in the actual target dynamics regime.
- Failure mode differs from B-Random: B stuck at cost~0.70 (max-speed local min). E stuck at cost~0.25 (optimizer flailing in flat gradient landscape, no clear direction). Cost init and final are nearly identical by Trial 3 onward — gradient signal is effectively zero.
- **Lesson:** Stratified exploration over full [0, uM] only works when the target range spans a substantial fraction of the speed range. When targets cluster near max range (as in E), a targeted exploration strategy is needed.

### Fix attempt 1 for E: Config E-Strat2 — targeted stratification over [2.5, uM]
- **Files:** `policy_learning/Policy.py` (added `u_min` param to `Stratified_Throwing_Exploration`), `test_mc_pilot_e_strat2.py`
- **Change:** Exploration bands now span [2.5, 3.5] m/s. All 5 throws land in target zone (errors 16–325mm vs 350–924mm before). 2 exploration near-hits.
- **Result: FAILED — same cost plateau at ~0.25.** Better exploration didn't help.
- **Diagnosis:** Exploration quality was NOT the primary bottleneck. Root cause is GP data scarcity: T=0.55s gives only 137 raw training points before Trial 1 (vs 250 for D-Strat). GP simulation consistently predicts ~0.38m errors while real throws achieve ~0.25m — inaccurate GP means optimizer stalls regardless of seed.

### Fix attempt 2 for E: Config E-Strat3 — Nexp=10, targeted stratification: FAILED
- **File:** `test_mc_pilot_e_strat3.py`
- **Change:** `Nexp=5 → 10`. 275 training points, finer speed bands [2.5–3.5].
- **Result:** 0/10 hits. Same cost plateau at ~0.25. Policy outputs exactly 3.500 m/s for EVERY target regardless of distance. **Confirmed: tanh saturation at max speed.**
- **Root cause identified:** With lc=0.5m > target range (0.35m), max-speed cost ≈ 0.25 (ball overshoots lM by ~0.3m). The cost landscape is so flat that max-speed is a stable local minimum — optimizer gradient can't distinguish between "slightly wrong speed" and "correct speed" within the target range. GP data quantity was not the issue.

### Fix attempt 3 for E: Config E-Strat4 — lc=0.25, Nexp=10, targeted stratification
- **File:** `test_mc_pilot_e_strat4.py`
- **Change:** `lc=0.5 → 0.25`. With lc=0.25, max-speed cost rises to ~0.69 (clearly penalised), near-optimal cost is ~0.05. Steep gradient forces optimizer away from saturation. Nexp=10 provides enough GP data (275 pts) to avoid gradient starvation at lc=0.25.
- **Result:** FAILED — 0/10 hits. Ball lands at exactly **1.156m** for every single trial regardless of target (targets ranged 0.80–1.02m). Cost stuck at 0.60–0.64 with no monotone trend (trial 3 cost actually increased). lc=0.25 was not the issue.
- **Root cause (revised):** lc addressed the wrong symptom. The actual failure is **RBF policy blindness**: with `lengthscales_init=[1.0, 1.0]`, the RBF sensitivity between Config E's target extremes (0.75m vs 1.10m, distance=0.35m) is `exp(-0.5*(0.35/1.0)²) = 0.941` — all targets produce nearly identical activation vectors `φ(P)`. The policy output `speed = squash(W·φ(P))` is therefore constant regardless of target. It converges to max speed because Gaussian MC particles with targets beyond lM=1.10m bias the "optimal constant" toward max speed. The lengthscale gradient is also near-zero (same reason), so the optimizer cannot self-correct. lc, Nexp, exploration strategy all addressed symptoms; this blindness was the root cause throughout E-Strat1–4.
- **Comparison:** Config A has a 1.0m target range with ls=1.0m → sensitivity=0.607 (targets distinguishable). Config E has 0.35m range → 0.941 (targets indistinguishable). Same lengthscale, very different resolution.

### Fix attempt 4 for E: Config E-Strat5 — lengthscales_init=[0.15, 0.15]
- **File:** `test_mc_pilot_e_strat5.py`
- **Change:** `lengthscales_init=[1.0, 1.0] → [0.15, 0.15]`. At ls=0.15m, sensitivity between Config E's extremes = `exp(-0.5*(0.35/0.15)²) = 0.066` — targets are clearly distinguishable, same resolution as Config A. Policy can now map near targets → low speed, far targets → high speed. All other settings from E-Strat4 retained (lc=0.25, Nexp=10, strat [2.5, 3.5]).
- **Result:** SUCCESS — **10/10 hits**. Ball distance per trial now tracks target distance (0.80–1.04m), confirming policy correctly varies speed by target — complete contrast to E-Strat4 where every throw was 1.156m. Trial 1: cost 0.786→0.010 (strong first-trial convergence). Trial 2 onward: cost already starts at 0.013–0.020, fully converged by trial 2. Mean error: 26mm, min: 20mm, max: 33mm. Tightest error band of all elevated configs.
- **Lesson:** For narrow target ranges, `lengthscales_init` must be scaled to the target range, not left at the paper's default of [1.0, 1.0]. Rule: `ls ≈ 0.1–0.2 × target_range` gives comparable resolution to configs that work at ls=1.0m with 1.0m range.

### General finding: lengthscales must scale with target range

The paper uses `lengthscales_init=[1.0, 1.0]` throughout. This works when the target range is ~1m wide but silently breaks for narrow target domains. The RBF sensitivity between two target positions at distance `d` apart is `exp(-0.5*(d/ls)²)`. When this is close to 1.0, the policy cannot distinguish between those targets and collapses to a constant output.

**Rule of thumb:** `ls ≈ 0.15 × target_range` keeps sensitivity at ~0.066 between the domain extremes — comparable to what Config A achieves with ls=1.0m over a 1.0m range. For any config with a narrow target arc, scale down `lengthscales_init` proportionally before running.

| Config | Target range | Recommended ls | Sensitivity at extremes |
|--------|-------------|----------------|------------------------|
| A–D (range ≥ 1.0m) | ≥ 1.0m | 1.0m (paper default) | ≤ 0.607 ✓ |
| E (range 0.35m) | 0.35m | **0.15m** | 0.066 ✓ |

This is the only parameter the paper does not adapt to geometry. Everything else (lM, T, exploration strategy) does adapt.

---

### Elevated configs summary

| Config | z_release | lM | Exploration | Seed | Result |
|--------|-----------|-----|-------------|------|--------|
| A | 0.5m | 1.75m | Random | 1 | 5/5 hits, mean err ~33mm |
| B | 1.0m | 1.90m | Random | 1 | 0/10 FAILED (bad seed) |
| B | 1.0m | 1.90m | Random | 2 | 10/10, mean err 20mm |
| B-Strat | 1.0m | 1.90m | Stratified | 1 | 10/10, mean err 20mm |
| C-Strat | 1.5m | 2.15m | Stratified | 1 | **10/10**, mean err ~14mm |
| D-Strat | 2.0m | 2.35m | Stratified | 1 | **10/10**, mean err ~16mm |
| E-Strat | 0.0m | 1.10m | Stratified [0, 3.5] | 1 | 0/10 FAILED — speed-range compression |
| E-Strat2 | 0.0m | 1.10m | Stratified [2.5, 3.5], Nexp=5 | 1 | 0/10 FAILED — GP data-starved |
| E-Strat3 | 0.0m | 1.10m | Stratified [2.5, 3.5], Nexp=10 | 1 | 0/10 FAILED — tanh saturation at max speed |
| E-Strat4 | 0.0m | 1.10m | Strat [2.5,3.5], Nexp=10, lc=0.25 | 1 | 0/10 FAILED — RBF blindness (ls=1m >> target range 0.35m) |
| E-Strat5 | 0.0m | 1.10m | Strat [2.5,3.5], Nexp=10, lc=0.25, ls=0.15 | 1 | **10/10**, mean err 26mm |

---

## Current Best Configuration

| Parameter | Value | Note |
|-----------|-------|------|
| `lc` | 0.5m | Wider than paper (0.1m) for gradient coverage |
| `Ts` | 0.02s | 2x paper value, ~3x speedup |
| `T` | 0.7s | Trimmed from 1.0s, ball lands by 0.58s |
| `lM` | 1.75m | Paper's value; 2.4m was beyond physical reach |
| `Nopt` | 1500 | Early stopping handles actual termination |
| `min_diff_cost` | 0.02 | Relaxed from 0.08 |
| `num_min_diff_cost` | 400 | Relaxed from 200 |
| `min_step` | 400 | Relaxed from 200 |
| Exploration | Random | Baseline policy gave worse GP coverage |
| Threads | 1 | Multi-threading counterproductive |

## Current Best Scores (seed=1, 5 trials, random exploration, lc=0.5, lM=1.75)

| Throw | Phase | Error (m) | Hit (<0.1m) | Target dist |
|-------|-------|-----------|-------------|-------------|
| 1–5 | Explore | 0.02–1.09m | — (1 accidental hit) | random |
| 6 | Trial 1 | **0.085m** | HIT | 1.66m |
| 7 | Trial 2 | **0.033m** | HIT | 1.60m |
| 8 | Trial 3 | **0.023m** | HIT | 1.18m |
| 9 | Trial 4 | **0.017m** | HIT | 0.79m |
| 10 | Trial 5 | **0.008m** | HIT | 1.10m |

**Summary:** 5/5 hits (100%). Cost converged from 0.74 → 0.009 (Trial 1) to 0.001 (Trial 5). Policy fully converged by Trial 5 (early stopped at step 1204).

---

### Experiment D: Match paper's center and weight initialization (Eq. 22)
- **Hypothesis:** Paper initializes centers over full Cartesian box `[0, lM] × [-lM·sin(gM), lM·sin(gM)]` and weights over `[-uM, uM]`. Our narrower ranges might be limiting policy coverage.
- **Changes:** Centers: `Px ∈ [0, 2.4]`, `Py ∈ [-1.2, 1.2]` (was `[0.65, 2.4] × [-0.375, 1.2]`). Weights: `[-uM, uM]` (was `[-uM/2, uM/2]`).
- **Result:** FAILED. Hit rate dropped from 50% to 0/10. Cost stuck at ~0.42 across all 10 trials (was reaching 0.13–0.17 before).
- **Root cause:** With lm=0.75m and gM=π/6, targets are always at distance ≥ 0.75m — so `xP < 0.65` is a dead zone. The wider center range wastes ~27% of the 250 centers on regions no target ever occupies, diluting RBF density in the actual target zone. Wider weights may also cause tanh saturation (larger raw values → flatter gradient landscape).
- **Lesson:** The paper's Eq. 22 domain is designed for their robot's geometry (lM=1.75m). Our target domain geometry is different enough that blindly copying it hurts. Centers should cover the actual reachable target arc, not a wider Cartesian box.

---

## Exploration 3: PyBullet Arm + Elevated Platforms (mc-pilot-pb-elevated/)

### Motivation

`mc-pilot-pybullet/` demonstrated PyBullet physics + visualisation, but only at z=0.5m release (Config PB-A) and with noise experiments (PB-B, PB-C). `mc-pilot-elevated/` proved 100% hit rates at multiple release heights (B/C/D-Strat, z=1.0/1.5/2.0m) using the numpy simulator. Neither folder combines both: visualisation of the multi-height experiment.

Goal: create `mc-pilot-pb-elevated/` that uses PyBullet arm + gui as the physics simulator and reproduces the B/C/D-Strat configs from elevated exactly (same hyperparameters) so the training converges identically and the result can be visualised with `demo_pybullet_gui.py`.

The E-config (ground-level, z=0.0m) was excluded: convergence was already demonstrated in mc-pilot-elevated/E-Strat5 and it requires additional config complexity (tight lengthscales, targeted stratification, lc=0.25) that is distracting in this context.

---

### Architecture decisions

**Why not modify mc-pilot-elevated directly?**
mc-pilot-elevated uses the numpy `ThrowingSystem` (no PyBullet), so it has no gui visualisation capability. Adding PyBullet to it would require duplicating the robot_arm/ machinery. It was cleaner to copy mc-pilot-pybullet (which already has all PyBullet plumbing) and adapt it to the elevated parameter sets.

**Folder created:** `cp -r mc-pilot-pybullet mc-pilot-pb-elevated`. The `mc-pilot-pybullet/` original is untouched.

**Files removed from the copy:** `test_mc_pilot_pb_B.py`, `test_mc_pilot_pb_C.py`, `test_mc_pilot_pb_A_noisy.py`, and their result directories (`results_mc_pilot_pb_A`, `results_mc_pilot_pb_A_noisy`, `results_mc_pilot_pb_B`, `results_mc_pilot_pb_C`). The noise-experiment scripts are irrelevant to the elevated visualization goal. `test_mc_pilot_pb_A.py` and `test_mc_pilot.py` retained as references.

**`arm_noise` hooks kept in `MC_PILCO.py`:** The `arm_noise=None` hook is a no-op when None is passed (no behavior change). Removing it would be churn with no benefit — it stays.

---

### Key engineering problem: iiwa7 velocity cap

KUKA iiwa7 joint velocity limits `[1.71, 1.71, 1.75, 2.27, 2.44, 3.14, 3.14]` rad/s cap EE speed at ~2.5 m/s for multi-joint motion. The B/C/D elevated configs require `uM=3.5 m/s`. This is physically impossible within hardware limits.

**Resolution chosen:** Scale joint velocity limits by `vel_limit_multiplier=1.5` inside the simulation. This is acceptable because:
1. The physical robot is never used — all results are from simulation
2. Ball velocity is set explicitly via `resetBaseVelocity` at release regardless of what the arm joints actually achieve; the arm motion is cosmetic
3. The `vel_limit_multiplier` only affects the feasibility clipping in `plan_throw` (the Jacobian pseudoinverse scaling step) — it does not change the delivered ball velocity

The arm still physically moves through its trajectory; only the internal check that prevents impossible joint velocities from being commanded is relaxed.

**Implementation:** `ArmController.__init__` accepts `vel_limit_multiplier=1.0` (new kwarg). Line changed: `self._qd_max = _IIWA_QD_MAX * vel_limit_multiplier`. Default 1.0 preserves all existing behavior in `mc-pilot-pybullet/`.

---

### Key engineering problem: arm height / reach

iiwa7 natural EE height at neutral pose is ~0.71m above its base. Release heights of 1.0m, 1.5m, 2.0m require EE to be at those z-values. If arm base is at z=0, IK for z=1.0m release requires the arm to stretch ~0.3m higher than its natural reach — likely IK failure.

**Resolution:** Mount arm on a pedestal by setting `base_position` in `ArmController` / `PyBulletThrowingSystem`:
- Config B (z_release=1.0m): `base_position=(0, 0, 0.5)` → EE neutral at z≈1.21m, IK target z=1.0m is 0.21m lower → reachable
- Config C (z_release=1.5m): `base_position=(0, 0, 1.0)` → EE natural at z≈1.71m, target z=1.5m → reachable
- Config D (z_release=2.0m): `base_position=(0, 0, 1.5)` → EE natural at z≈2.21m, target z=2.0m → reachable

**Implementation:** `PyBulletThrowingSystem.__init__` accepts `base_position=(0,0,0)` and `vel_limit_multiplier=1.0` (new kwargs). Both stored and passed to `ArmController` inside `_simulate_pybullet`. `ArmController` already had `base_position` in its signature — no change needed there beyond adding `vel_limit_multiplier`.

**Verification (headless):** `standalone_throw.py --direct --speed 3.5 --target_dist 1.5 --z_release 1.0` confirmed:
- v_cmd correctly set to 3.5 m/s (`v_release=3.500`)
- Ball lands at 2.099m from z=1.0 (max range at uM=3.5 ≈ 2.1m; matches mc-pilot-elevated's verified 1.97m with expected ~5–10% PyBullet drag offset)
- No errors; clean landing detection

---

### Files modified

#### robot_arm/arm_controller.py
- Added `vel_limit_multiplier=1.0` kwarg to `__init__`
- Changed `self._qd_max = _IIWA_QD_MAX.copy()` → `self._qd_max = _IIWA_QD_MAX * vel_limit_multiplier`
- Docstring updated to document the new parameter and its simulation-only caveat

#### simulation_class/model_pybullet.py
- Added `base_position=(0,0,0)` and `vel_limit_multiplier=1.0` kwargs to `__init__`
- Stored as `self._base_position` and `self._vel_limit_multiplier`
- `_simulate_pybullet`: changed `ArmController(client, self._urdf_path)` → `ArmController(client, self._urdf_path, base_position=self._base_position, vel_limit_multiplier=self._vel_limit_multiplier)`

#### standalone_throw.py
- Added `--z_release` arg (default 1.0): release height in meters
- Added `--vel_mult` arg (default 1.5): joint velocity limit multiplier
- `ARM_BASE_POS` auto-set to `(0, 0, z_release - 0.5)`
- `RELEASE_POS` now `[0, 0, z_release]` (was hardcoded to `[0.5, 0, 0.5]`)
- `T_TOTAL` scaled with z_release: `max(1.5, z_release * 0.6 + 1.0)` (longer horizon for higher releases)
- Default `--speed 3.5, --target_dist 1.5` to match the elevated config range

---

### New test scripts

All three scripts mirror their `mc-pilot-elevated` counterparts (`test_mc_pilot_b_strat.py`, `c_strat.py`, `d_strat.py`) exactly in hyperparameters. The only differences from the numpy elevated versions are:
1. `PyBulletThrowingSystem(base_position=..., vel_limit_multiplier=1.5)` instead of `ThrowingSystem`
2. No `arm_noise` arg in `MC_PILOT` (zero noise — deterministic throws)
3. Log dirs prefixed `results_mc_pilot_pbe_*` to avoid collision

| Script | z_release | ARM_BASE_POS | lM | T | lengthscales_init |
|--------|-----------|--------------|-----|-----|-------------------|
| `test_mc_pilot_pbe_B.py` | 1.0 m | [0, 0, 0.5] | 1.90 m | 0.85 s | [1.0, 1.0] |
| `test_mc_pilot_pbe_C.py` | 1.5 m | [0, 0, 1.0] | 2.15 m | 0.95 s | [1.0, 1.0] |
| `test_mc_pilot_pbe_D.py` | 2.0 m | [0, 0, 1.5] | 2.35 m | 1.00 s | [1.0, 1.0] |

Shared across all three: `Nexp=5, Nopt=1500, M=400, Nb=250, uM=3.5, lm=0.75, lc=0.5, Ts=0.02, gM=π/6`. Exploration uses `Stratified_Throwing_Exploration` over full `[0, uM]` (no `u_min`), matching B/C/D-Strat from elevated.

**Expected results:** 10/10 hits on each (matching the 100% hit rates from mc-pilot-elevated B/C/D-Strat, seed=1). The numpy and PyBullet sims use identical ball physics (same Eq. 35 drag, same landing detection, same explicit velocity setting at release), so convergence should be equivalent.

**Visualisation:** After training, run: `python demo_pybullet_gui.py --log_path results_mc_pilot_pbe_B/1`

---

### PyBullet vs numpy physics discrepancy note

The standalone_throw test shows uM=3.5 from z=1.0m reaches ~2.1m in PyBullet vs the numpy elevated's verified lM=1.90m at max range (~1.97m). There is a ~5–10% range discrepancy. This does not affect convergence because:
1. The GP learns from *actual PyBullet throws*, not from numpy predictions
2. lM=1.90m is still safely within the PyBullet arm's reach (ball can reach 2.1m, target max is 1.9m → margin of 0.2m)
3. The policy will learn the correct speed-to-range mapping for PyBullet's physics, which is what matters

The discrepancy will cause the trained policy to pick slightly different speeds than the numpy elevated policy, but the hit rate should be identical because the GP model is fitted to PyBullet data.
