"""
rcb_robodojo.py — task-local tooling for RoboDojo's simulation benchmark (github.com/RoboDojo-Benchmark/RoboDojo @ cb2a37d,
MIT; Isaac Sim 5.1 + RoboDojo's Isaac Lab 2.3 fork, PhysX): frozen task instance / privileged helpers / action recording /
fresh-process replay. Same shape as the YAMLab tasks' rcb_yamlab.py, so agents and verifiers share one mental model.

Concepts
--------
instance   : one RoboDojo task on one of RoboDojo's own evaluation layouts (Assets/Eval_Layout/RoboDojo/arx_x5/<seed>/
             <task>_<n>.json: every object's category, asset, pose, scale and physics, the table, room, lighting and
             background), frozen verbatim in instance.json ("layout", with its sha256). Session(instance=...) builds RoboDojo's
             evaluation environment for the task (one env, the dual ARX X5 setup RoboDojo evaluates on) and resets it onto
             that layout exactly as RoboDojo's evaluator does (scene reload, robot reset, the evaluator's settling steps).
             `state_sha` = sha1 over every rigid body's world pose and the robots' joint positions.
trajectory : the (T, 14) actions handed to RoboDojo's evaluator, one row per control step (25 Hz: physics dt 4 ms, each
             action interpolated over 10 physics steps by RoboDojo's own controller): [left joint1..6, left gripper, right
             joint1..6, right gripper]. Joints are absolute position targets (rad); a gripper entry is RoboDojo's normalised
             gripper command (0..1, clipped). Only actions enter scoring.
success    : RoboDojo's own reward manager for the task (its `run_reward` check list, evaluated after every action as in
             RoboDojo's evaluator); the episode ends as RoboDojo's does: at the first action where the task's checks all
             pass (success) or when a check fails for good. RoboDojo's evaluation also ends a policy's episode after the
             task's step_lim actions; no task's check reads that limit, and here there is none (PROTOCOL D1: no step caps),
             only the runaway guard MAX_ACTIONS.

CLI
---
  python rcb_robodojo.py make-instance --task stack_bowls --seed 0 --layout 0 --out instance.json
  python rcb_robodojo.py run-actions   --task stack_bowls --instance instance.json --actions actions.npy --out traj.npz
  python rcb_robodojo.py replay        --task stack_bowls --instance instance.json --traj traj.npz [--video replay.mp4]

Python (what the agent gets)
----------------------------
  from rcb_robodojo import Session
  s = Session("stack_bowls", instance="/app/instance.json")   # a few minutes: Isaac Sim launch + scene build + settling
  s.reset()                          # back to the frozen layout (unlimited)
  s.instruction()                    # RoboDojo's language instruction for this layout
  s.objects()                        # label -> category, position, orientation_wxyz, bbox corners
  s.render_frame("cam_head")         # RGB (480, 640, 3) uint8; "cam_head", "cam_left_wrist", "cam_right_wrist"
  s.step(a)                          # one action (14 entries) = one control step (1/25 s)
  s.record_start(); ...; actions = s.record_stop()
  s.status()                         # {'success', 'done', 'end_reason', 'actions', 'max_actions', 'state_sha', ...}
  s.replay(actions); s.save_trajectory(actions, "/app/output/trajectory.npz")
"""
from __future__ import annotations

import os
os.environ.setdefault("OMNI_KIT_ACCEPT_EULA", "YES")
os.environ.setdefault("ACCEPT_EULA", "Y")
os.environ.setdefault("OMNI_KIT_ALLOW_ROOT", "1")
os.environ.setdefault("PYTHONUNBUFFERED", "1")

import argparse
import hashlib
import json
import sys
import time
from copy import deepcopy
from pathlib import Path
from typing import Any, Callable

import numpy as np

ROBODOJO_ROOT = Path(os.environ.get("ROBODOJO_ROOT", "/opt/RoboDojo"))
SESSION_LOG = os.environ.get("RCB_SESSION_LOG", "/app/output/rcb_session_log.jsonl")
SESSION_LOG_KEEP = os.environ.get("RCB_SESSION_LOG_KEEP", "/logs/agent/rcb_session_log.jsonl")
CONFIG_NAME = "arx_x5"                 # RoboDojo's simulation embodiment: two ARX X5 arms with parallel grippers
CONTROL_HZ = 25
ACTION_DIM = 14
MAX_ACTIONS = 15000                    # no step budget (PROTOCOL D1; the wall clock is): this only stops a runaway episode (10 min of simulated time)
ARMS = ("left", "right")
ARM_SLICE = {"left": slice(0, 6), "right": slice(7, 13)}
GRIP_INDEX = {"left": 6, "right": 13}
CAMERAS = ("cam_head", "cam_left_wrist", "cam_right_wrist")
ACTION_LAYOUT = ("14 entries per control step (25 Hz), RoboDojo's joint action: left joint1..6, left gripper, right joint1..6, "
                 "right gripper; joints are absolute position targets (rad), grippers RoboDojo's normalised command (0..1)")
_APP = None


def _log(*a: Any) -> None:
    print("[rcb_robodojo]", *a, file=sys.stderr, flush=True)


def _slog(ev: str, **kw) -> None:
    if not SESSION_LOG:
        return
    line = json.dumps({"ts": time.time(), "pid": os.getpid(), "ev": ev, **kw}) + "\n"
    for path in (SESSION_LOG, SESSION_LOG_KEEP):
        if not path or (path == SESSION_LOG_KEEP and not os.path.isdir(os.path.dirname(path))):
            continue
        try:
            os.makedirs(os.path.dirname(path), exist_ok=True)
            with open(path, "a") as f:
                f.write(line)
        except OSError:
            pass


class PrimitiveError(RuntimeError):
    pass


class _quiet_progress:
    """RoboDojo's evaluator prints "env0 step: k / N" + carriage return on every action; keep everything else it prints."""

    def __enter__(self):
        import io
        self._buf, self._old = io.StringIO(), sys.stdout
        sys.stdout = self._buf

    def __exit__(self, *exc):
        sys.stdout = self._old
        import re
        rest = re.sub(r"env\d+ step: \S+ / \d+\S*\r?", "", self._buf.getvalue())
        if rest.strip():
            sys.stdout.write(rest)
        return False


def _np(x) -> np.ndarray:
    if hasattr(x, "detach"):
        x = x.detach().cpu().numpy()
    return np.asarray(x, dtype=np.float64)


def _launch_app():
    global _APP
    if _APP is None:
        sys.path[:0] = [str(ROBODOJO_ROOT), str(ROBODOJO_ROOT / "XPolicyLab")]
        from isaaclab.app import AppLauncher
        ap = argparse.ArgumentParser()
        AppLauncher.add_app_launcher_args(ap)
        args = ap.parse_args([])
        args.headless, args.enable_cameras = True, True
        from env.camera_manager.capture.render_sync import add_zero_delay_kit_args
        add_zero_delay_kit_args(args)          # as RoboDojo's evaluator: camera frames never lag physics
        _APP = AppLauncher(args).app
    return _APP


class _NoPolicy:
    """RoboDojo's evaluator talks to a policy server over a WebSocket; here the agent drives the env directly."""

    def __init__(self, *a, **k):
        pass

    def call(self, *a, **k):
        return None

    def close(self):
        pass


def quat_to_mat(q) -> np.ndarray:
    w, x, y, z = np.asarray(q, dtype=np.float64) / np.linalg.norm(q)
    return np.array([[1 - 2 * (y * y + z * z), 2 * (x * y - w * z), 2 * (x * z + w * y)],
                     [2 * (x * y + w * z), 1 - 2 * (x * x + z * z), 2 * (y * z - w * x)],
                     [2 * (x * z - w * y), 2 * (y * z + w * x), 1 - 2 * (x * x + y * y)]])


def mat_to_quat(R) -> np.ndarray:
    R = np.asarray(R, dtype=np.float64)
    t = np.trace(R)
    if t > 0:
        s = 2 * np.sqrt(t + 1); q = [0.25 * s, (R[2, 1] - R[1, 2]) / s, (R[0, 2] - R[2, 0]) / s, (R[1, 0] - R[0, 1]) / s]
    elif R[0, 0] > R[1, 1] and R[0, 0] > R[2, 2]:
        s = 2 * np.sqrt(1 + R[0, 0] - R[1, 1] - R[2, 2]); q = [(R[2, 1] - R[1, 2]) / s, 0.25 * s, (R[0, 1] + R[1, 0]) / s, (R[0, 2] + R[2, 0]) / s]
    elif R[1, 1] > R[2, 2]:
        s = 2 * np.sqrt(1 + R[1, 1] - R[0, 0] - R[2, 2]); q = [(R[0, 2] - R[2, 0]) / s, (R[0, 1] + R[1, 0]) / s, 0.25 * s, (R[1, 2] + R[2, 1]) / s]
    else:
        s = 2 * np.sqrt(1 + R[2, 2] - R[0, 0] - R[1, 1]); q = [(R[1, 0] - R[0, 1]) / s, (R[0, 2] + R[2, 0]) / s, (R[1, 2] + R[2, 1]) / s, 0.25 * s]
    q = np.asarray(q); q /= np.linalg.norm(q)
    return q if q[0] >= 0 else -q


def pose7(T) -> list[float]:
    return [round(float(x), 6) for x in list(T[:3, 3]) + list(mat_to_quat(T[:3, :3]))]


def _rpy(r, p, y) -> np.ndarray:
    cr, sr, cp, sp, cy, sy = np.cos(r), np.sin(r), np.cos(p), np.sin(p), np.cos(y), np.sin(y)
    return np.array([[cy * cp, cy * sp * sr - sy * cr, cy * sp * cr + sy * sr],
                     [sy * cp, sy * sp * sr + cy * cr, sy * sp * cr - cy * sr],
                     [-sp, cp * sr, cp * cr]])


def _axis_rot(axis, a) -> np.ndarray:
    k = np.asarray(axis, dtype=np.float64); k /= np.linalg.norm(k)
    K = np.array([[0, -k[2], k[1]], [k[2], 0, -k[0]], [-k[1], k[0], 0]])
    return np.eye(3) + np.sin(a) * K + (1 - np.cos(a)) * K @ K


class X5Model:
    """One ARX X5 arm from its URDF (joint1..joint6 to link6, and the wrist camera link), at its base pose."""

    def __init__(self, urdf: str, base_pos, base_quat_wxyz):
        import xml.etree.ElementTree as ET
        root = ET.parse(urdf).getroot()
        self.joints = {}
        for j in root.findall("joint"):
            o = j.find("origin")
            xyz = [float(v) for v in (o.get("xyz", "0 0 0") if o is not None else "0 0 0").split()]
            rpy = [float(v) for v in (o.get("rpy", "0 0 0") if o is not None else "0 0 0").split()]
            ax = j.find("axis")
            T = np.eye(4); T[:3, :3] = _rpy(*rpy); T[:3, 3] = xyz
            self.joints[j.find("child").get("link")] = {"name": j.get("name"), "parent": j.find("parent").get("link"), "type": j.get("type"), "T": T,
                                           "axis": [float(v) for v in ax.get("xyz").split()] if ax is not None else None}
        self.base = np.eye(4); self.base[:3, :3] = quat_to_mat(base_quat_wxyz); self.base[:3, 3] = base_pos
        self.chain = [f"link{i}" for i in range(1, 7)]

    def fk(self, q6) -> dict[str, np.ndarray]:
        out, T = {}, self.base.copy()
        for i, link in enumerate(self.chain):
            j = self.joints[link]
            R = np.eye(4); R[:3, :3] = _axis_rot(j["axis"], float(q6[i]))
            T = T @ j["T"] @ R
            out[link] = T.copy()
        for link in ("camera_base", "camera"):
            if link in self.joints and self.joints[link]["parent"] in out:
                out[link] = out[self.joints[link]["parent"]] @ self.joints[link]["T"]
        return out

    def ik(self, target7, seed6, iters: int = 300):
        p_t, R_t = np.asarray(target7[:3]), quat_to_mat(target7[3:7])
        q = np.asarray(seed6, dtype=np.float64).copy()

        def err(q):
            T = self.fk(q)["link6"]
            dp = p_t - T[:3, 3]
            Re = R_t @ T[:3, :3].T
            ang = np.arccos(np.clip((np.trace(Re) - 1) / 2, -1, 1))
            w = np.array([Re[2, 1] - Re[1, 2], Re[0, 2] - Re[2, 0], Re[1, 0] - Re[0, 1]])
            dw = (ang / (2 * np.sin(ang)) * w) if ang > 1e-6 else 0.5 * w
            return np.concatenate([dp, dw])
        for _ in range(iters):
            e = err(q)
            if np.linalg.norm(e[:3]) < 1e-4 and np.linalg.norm(e[3:]) < 1e-3:
                break
            J = np.zeros((6, 6)); h = 1e-6
            for k in range(6):
                dq = np.zeros(6); dq[k] = h
                J[:, k] = -(err(q + dq) - e) / h
            dq = J.T @ np.linalg.solve(J @ J.T + 1e-4 * np.eye(6), e)     # J = d(current pose)/dq, e = target - current
            q += dq * min(1.0, 0.2 / max(1e-9, float(np.abs(dq).max())))
        e = err(q)
        return q, {"pos_m": float(np.linalg.norm(e[:3])), "rot_rad": float(np.linalg.norm(e[3:]))}


class Session:
    def __init__(self, task: str, instance: str | Path | dict | None = None, *, seed: int = 0, layout: int = 0,
                 strict: bool = False, depth: bool = False, physx: dict | None = None):
        inst = None
        if instance is not None:
            inst = instance if isinstance(instance, dict) else json.load(open(instance))
            if inst.get("task") != task:
                raise ValueError(f"instance task {inst.get('task')} != session task {task}")
            seed, layout = int(inst["seed"]), int(inst["layout_index"])
        self.task, self.inst = task, inst
        self.depth_enabled = bool(depth)
        # PhysX settings of this frozen instance on top of RoboDojo's (sim_config "physx", e.g. enable_enhanced_determinism):
        # recorded in instance.json, so the agent's sessions, the standard service and the grader all run the same physics
        self.physx = dict((inst or {}).get("physics") or {}) if physx is None else dict(physx)
        t0 = time.time()
        _log(f"launching Isaac Sim (headless, cameras on) for RoboDojo task {task}; a few minutes (the first start in a container "
             f"also compiles shaders) ...")
        self.app = _launch_app()
        cwd = os.getcwd()
        os.makedirs("/tmp/robodojo-run", exist_ok=True)
        os.chdir("/tmp/robodojo-run")           # RoboDojo's evaluator writes eval_result/ under the working directory
        try:
            self.env = self._make_env(seed)
        finally:
            os.chdir(cwd)
        layout_data = inst["layout"] if inst is not None else None
        # the layout index stays RoboDojo's own (some tasks key per-layout data on it, e.g. the support arm's recorded
        # trajectory in imitate_sorting_sequence and make_kong); the layout itself comes from instance.json
        self._layout_id = int(layout)
        if layout_data is not None:
            self.env.seed_manager.get_seed_scene_info = lambda _seed, _d=layout_data: deepcopy(_d)
            self.env.seed_manager.seed_info = {self._layout_id: {"scene_layout": "instance.json"}}
        self.layout_data = layout_data if layout_data is not None else self.env.seed_manager.get_seed_scene_info(self._layout_id)
        self.env._stream_vision = lambda *a, **k: None   # the evaluator's per-frame video streaming: not wanted here
        self._recording: list[np.ndarray] | None = None
        self._video: dict | None = None
        self.n_steps = 0
        self._resets = -1
        self._end_logged = False
        _slog("session_start", task=task)
        import atexit
        atexit.register(self._log_end)
        self.reset()
        self.instance_sha = self.state_sha()
        expected = inst.get("state_sha") if inst else None
        self.instance_exact = expected is None or expected == self.instance_sha
        if not self.instance_exact:
            msg = f"instance state sha {self.instance_sha} != expected {expected} (a different GPU / driver, or version drift?)"
            # a task graded by verdict (instance.json "determinism": "verdict") has resets that are not bit-identical (GPU
            # PhysX particles; instance.json says why), so its rebuilt hash differs by design and `strict` does not apply
            if (inst or {}).get("determinism") == "verdict":
                _log(f"instance state sha {self.instance_sha} (recorded {expected}): expected for this task, graded by verdict "
                     "(its resets are not bit-identical)")
            elif strict:
                raise RuntimeError(msg)
            else:
                _log("WARNING:", msg)
        _log(f"instance ready in {time.time() - t0:.0f}s; state_sha={self.instance_sha}; no step cap (runaway guard {self.step_lim}); "
             f"instruction: {self.instruction()!r}")

    # ---- env construction: RoboDojo's own evaluator environment (src/eval_client), one env, no policy server
    def _make_env(self, seed: int):
        import importlib
        from omegaconf import OmegaConf
        import src.eval_client.eval_env as ee
        ee.WsModelClient = _NoPolicy
        from env.global_configs import BENCHMARK, ENV_CONFIG_PATH, ROOT_DIR
        from utils.load_file import load_yaml
        from utils.pipeline_utils import process_config, process_randomization
        reg = importlib.import_module(f"task.{BENCHMARK}.task_registry")
        eval_cfg = load_yaml(os.path.join(ENV_CONFIG_PATH, CONFIG_NAME + ".yml"))
        eval_cfg.update(task_name=self.task, num_envs=1, device_id=0, eval_batch=False, policy_name="rcb",
                        additional_info="rcb", seed=int(seed), physx_monitor_enabled=False)
        c = eval_cfg["config"]
        cfg = OmegaConf.create({
            "sim": load_yaml(os.path.join(ENV_CONFIG_PATH, "sim", c["sim"] + ".yml")),
            "scene": load_yaml(os.path.join(ENV_CONFIG_PATH, "scene", c["scene"] + ".yml")),
            "camera": load_yaml(os.path.join(ENV_CONFIG_PATH, "camera", c["camera"] + ".yml")),
            "robot": load_yaml(os.path.join(ENV_CONFIG_PATH, "robot", c["robot"] + ".yml")),
            "task_env": load_yaml(reg.task_config_path(os.path.join(ROOT_DIR, "task", BENCHMARK, "config"), self.task)),
            "eval_cfg": eval_cfg, "deploy_cfg": {"policy_name": "rcb", "port": 1, "host": "localhost"}})
        OmegaConf.update(cfg, "sim.scene.num_envs", 1, force_add=True)
        for k, v in self.physx.items():
            OmegaConf.update(cfg, f"sim.physx.{k}", v, force_add=True)
        if self.depth_enabled:   # rendering only: the cameras' z-depth annotators (commented out in RoboDojo's camera config)
            OmegaConf.update(cfg, "eval_cfg.observation.vision.depth", True, force_add=True)
            for cam in CAMERAS:
                if cam in cfg.camera.get("annotator", {}):
                    OmegaConf.update(cfg, f"camera.annotator.{cam}.distance_to_image_plane_capture",
                                     {"type": "distance_to_image_plane", "device": "cpu"}, force_add=True)
        cfg = process_randomization(cfg)
        cfg, _ = process_config(cfg, task_name=self.task)
        OmegaConf.update(cfg, "camera.default_frequency", eval_cfg["observation"].get("collect_freq", 0), force_add=True)
        cfg.sim.seed = [0]
        env = ee.create_eval_env(cfg, self.app)
        # RoboDojo's evaluation gives a policy step_lim actions per episode; no task's check reads it (none registers an
        # end-of-episode check), it only ends the episode. Here there is no step cap (PROTOCOL D1): the episode runs until
        # the check passes or fails for good, or until the runaway guard MAX_ACTIONS.
        self.robodojo_step_lim = int(env.step_lim)
        env.step_lim = MAX_ACTIONS
        self.step_lim = MAX_ACTIONS
        return env

    # ---- episode
    def reset(self) -> None:
        """Back to the frozen layout, as RoboDojo's evaluator starts an episode (scene reload, robot reset, the settling
        steps); unlimited. Right after a reset (nothing stepped since) it changes nothing, so the first replay in a process
        starts exactly where the grader's fresh processes start. After actions, RoboDojo's reset settles the scene again
        from where it is: the layout and the robot's start are the same, the last digits of a few poses may not be, so a
        replay after a later reset can end slightly differently from the grader's (self-check with the replay CLI)."""
        if getattr(self, "_pristine", False):
            self.n_steps = 0
            return
        env = self.env
        env.success, env.end_flag, env.take_action_cnt = [True], [False], [0]
        env.episode_nums, env.unstable_nums = 1, 0
        env.reset(seed=[self._layout_id])
        # the start of RoboDojo's episode (EvalEnv.run_eval): register the task's checks, its process score, and for the
        # interactive tasks the support arm's first move; then the policy loop, i.e. step()
        env.run_reward()
        # RoboDojo's reward manager reports success once its check lists are empty (reward_manager.get_reward): a task that
        # registered no check would succeed at the first action. Every task registers one; refuse to run otherwise.
        rm = getattr(env, "reward_manager", None)
        if rm is None or not any(len(getattr(rm, k)[0]) for k in ("check_list", "final_check_list", "trigger_check_list")):
            raise RuntimeError(f"RoboDojo registered no success check for task {self.task}: the episode would read as a success at once")
        if hasattr(env, "get_score"):
            env.get_score()
        if getattr(env, "interact", False) and hasattr(env, "query_support_arm_traj"):
            env.query_support_arm_traj(env_idx=0)
        self.n_steps = 0
        self._resets += 1
        obs = env.get_obs()
        self._keys = self._action_keys(obs)
        self._targets = self._obs_action(obs)
        self._pristine = True
        if self._resets:
            _slog("reset", task=self.task)

    def _action_keys(self, obs) -> dict[str, str]:
        act = obs["action"]
        keys = {}
        for arm in ARMS:
            keys[f"{arm}_arm"] = next(k for k in act if k.startswith(arm) and k.endswith("arm_joint_state"))
            keys[f"{arm}_ee"] = next(k for k in act if k.startswith(arm) and k.endswith("ee_joint_state"))
        return keys

    def _obs_action(self, obs) -> np.ndarray:
        a = np.zeros(ACTION_DIM)
        act = obs["action"]
        for arm in ARMS:
            a[ARM_SLICE[arm]] = np.asarray(act[self._keys[f"{arm}_arm"]], dtype=np.float64)[:6]
            a[GRIP_INDEX[arm]] = float(np.asarray(act[self._keys[f"{arm}_ee"]], dtype=np.float64).reshape(-1)[0])
        return a

    def _to_dict(self, a: np.ndarray) -> dict[str, np.ndarray]:
        out = {}
        for arm in ARMS:
            out[self._keys[f"{arm}_arm"]] = a[ARM_SLICE[arm]].astype(np.float64)
            out[self._keys[f"{arm}_ee"]] = a[GRIP_INDEX[arm]:GRIP_INDEX[arm] + 1].astype(np.float64)
        return out

    @property
    def done(self) -> bool:
        return bool(self.env.end_flag[0])

    def success(self) -> bool:
        return bool(self.env.end_flag[0]) and bool(self.env.success[0])

    def end_reason(self) -> str | None:
        if not self.done:
            return None
        if self.success():
            return "success"
        return "step_guard" if self.env.take_action_cnt[0] >= self.step_lim else "failed_check"

    def step(self, action) -> bool:
        """Apply one action (14 entries, ACTION_LAYOUT) for one control step (1/25 s) through RoboDojo's evaluator
        (`take_action`: interpolation over 10 physics steps, the task's checks, the episode end). Returns True when the
        episode is over (success, a failed check, or the step limit); further steps raise until reset()."""
        a = np.asarray(action, dtype=np.float64).reshape(-1)
        if a.size != ACTION_DIM:
            raise ValueError(f"action must have {ACTION_DIM} entries, got {a.size}")
        # a trajectory file holds float32 rows and the grader replays those: execute exactly the row that is recorded, so a
        # live rollout and its replay get the same targets to the last bit (the standard service does the same)
        with np.errstate(over="ignore"):
            a = a.astype(np.float32).astype(np.float64)
        if not np.all(np.isfinite(a)):
            raise ValueError("action contains nan/inf (or a value outside float32)")
        if self.done:
            raise PrimitiveError(f"episode is over ({self.end_reason()}); call reset() before stepping again")
        if self._recording is not None:
            self._recording.append(a.astype(np.float32))
        self._pristine = False
        with _quiet_progress():
            self.env.take_action(self._to_dict(a))
        self._targets = a.copy()
        self.n_steps += 1
        if self._video is not None and not self._video.get("failed") and self.n_steps % self._video["every"] == 0:
            self._video_add()
        return self.done

    def hold_action(self) -> np.ndarray:
        """The action that keeps the current joint targets and gripper commands."""
        return self._targets.copy()

    def status(self) -> dict[str, Any]:
        return {"success": self.success(), "done": self.done, "end_reason": self.end_reason(), "actions": int(self.n_steps),
                "max_actions": self.step_lim, "resets": self._resets, "state_sha": self.state_sha()}

    # ---- state hash: every rigid body's world pose (PhysX) + both arms' joint positions (+ particle positions, if any)
    def state_sha(self) -> str:
        from pxr import UsdGeom, UsdPhysics
        import omni.physx
        import omni.usd
        stage = omni.usd.get_context().get_stage()
        px = omni.physx.get_physx_interface()
        vals: list[float] = []
        for prim in stage.Traverse():
            if prim.HasAPI(UsdPhysics.RigidBodyAPI):
                tr = px.get_rigidbody_transformation(str(prim.GetPath()))
                if tr and tr.get("ret_val"):
                    vals += list(tr["position"]) + list(tr["rotation"])
            elif prim.GetTypeName() in ("Points", "Mesh") and prim.HasAttribute("physxParticle:particleEnabled"):
                pts = UsdGeom.PointBased(prim).GetPointsAttr().Get()
                if pts is not None:
                    vals += np.asarray(pts, dtype=np.float64).ravel().tolist()
        for r in self.env.robot_manager.robot_list:
            j = self.env.robot_manager.get_joint(r, env_idx_list=[0])[0]
            if j is not None:
                vals += np.asarray(j, dtype=np.float64).ravel().tolist()
        return hashlib.sha1(np.round(np.asarray(vals, dtype=np.float64), 9).tobytes()).hexdigest()[:16]

    # ---- recording / trajectories
    def record_start(self) -> None:
        self._recording = []

    def record_stop(self) -> np.ndarray:
        acts = np.stack(self._recording) if self._recording else np.zeros((0, ACTION_DIM), np.float32)
        self._recording = None
        _slog("record", task=self.task, n_actions=int(len(acts)))
        return acts.astype(np.float32)

    def save_trajectory(self, actions: np.ndarray, path: str | Path, meta: dict | None = None) -> None:
        np.savez(path, actions=np.asarray(actions, dtype=np.float32), task=self.task, instance_sha=self.instance_sha,
                 action_dim=ACTION_DIM, action_layout=ACTION_LAYOUT, meta=json.dumps(meta or {}))

    def replay(self, actions: np.ndarray) -> dict[str, Any]:
        """reset(), then the actions open-loop until the episode ends. The grader does the same in fresh processes."""
        self.reset()
        for a in np.asarray(actions, dtype=np.float64):
            if self.step(a):
                break
        st = self.status()
        _slog("replay", task=self.task, n_actions=int(len(actions)), success=st["success"])
        return st

    # ---- observation: cameras and proprioception (rendering never steps physics)
    def observe(self) -> dict:
        """RoboDojo's observation (all cameras rendered at once), cached until the next step or reset."""
        key = (self._resets, self.n_steps)
        if getattr(self, "_obs_key", None) != key:
            self._obs, self._obs_key = self.env.get_obs(), key
        return self._obs

    def render_frame(self, camera: str = "cam_head") -> np.ndarray:
        v = self.observe()["vision"][camera]
        for k in ("rgb", "colors", "color"):
            if k in v:
                return np.ascontiguousarray(np.asarray(v[k])[..., :3]).astype(np.uint8)
        raise KeyError(f"no colour image for {camera}: {list(v)}")

    def render_depth(self, camera: str = "cam_head") -> np.ndarray:
        """z-depth (m, float32, 0 = no reading) of one camera; needs Session(..., depth=True)."""
        if not self.depth_enabled:
            raise PrimitiveError("depth is off: Session(..., depth=True)")
        d = np.asarray(self.observe()["vision"][camera]["depth"], dtype=np.float32)
        return np.where(np.isfinite(d), d, 0.0).astype(np.float32)

    def render_grid(self, cameras: tuple[str, ...] = CAMERAS) -> np.ndarray:
        return np.concatenate([self.render_frame(c) for c in cameras], axis=1)

    def _arm(self, arm: str):
        rm = self.env.robot_manager
        robot = next(r for r in rm.robot_list if r.type == "target" and r.arm_name.startswith(arm))
        return robot, rm.robot_key[rm.robot_list.index(robot)]

    def proprio(self) -> dict[str, list]:
        """Both arms, left then right: joint_pos (6 arm joints + the gripper joint, m), joint_vel, tcp_pose (link6: x y z
        qw qx qy qz, env frame), gripper_cmd (the normalised commands in force, 0..1), gripper_opening (the measured gripper
        joint mapped to 0..1, 1 = fully open), joint_effort (the arm joints' applied torques, N m)."""
        out: dict[str, list] = {k: [] for k in ("joint_pos", "joint_vel", "tcp_pose", "gripper_cmd", "gripper_opening", "joint_effort")}
        st = self.observe()["state"]
        for arm in ARMS:
            robot, key = self._arm(arm)
            ai, gi = list(robot.arm_joint_indices), list(robot.gripper_joint_indices)[:1]
            q, qd = _np(key.data.joint_pos)[0], _np(key.data.joint_vel)[0]
            eff = _np(getattr(key.data, "applied_torque", key.data.joint_pos * 0))[0]
            lo, hi = robot.gripper_scale
            out["joint_pos"] += [float(q[i]) for i in ai + gi]
            out["joint_vel"] += [float(qd[i]) for i in ai + gi]
            out["tcp_pose"] += [float(x) for x in np.asarray(st[f"{arm}_ee_pose"], dtype=np.float64).reshape(-1)[:7]]
            out["gripper_cmd"].append(float(self._targets[GRIP_INDEX[arm]]))
            out["gripper_opening"].append(float(np.clip((q[gi[0]] - lo) / (hi - lo), 0.0, 1.0)))
            out["joint_effort"] += [float(eff[i]) for i in ai]
        return out

    def robot_spec(self) -> dict:
        spec = {"arms": {}, "control": {"hz": CONTROL_HZ, "physics_dt_s": 0.004, "physics_steps_per_action": 10,
                                        "interpolation": "RoboDojo's: linear from the measured joints to the targets over 8 physics "
                                                         "steps, then 2 holding"}}
        for arm in ARMS:
            robot, key = self._arm(arm)
            lim = _np(key.data.soft_joint_pos_limits)[0]
            names = list(key.joint_names)
            ai = list(robot.arm_joint_indices)
            root = _np(key.data.root_pose_w)[0]
            spec["arms"][arm] = {"joints": {f"{arm}_{names[i]}": [round(float(lim[i, 0]), 4), round(float(lim[i, 1]), 4)] for i in ai},
                                 "base_pose": [round(float(x), 4) for x in root[:7]], "tool_frame": f"{arm}_link6",
                                 "gripper": {"command": "normalised 0..1 (1 = fully open, 0 = closed)",
                                             "joint_range_m": [float(robot.gripper_scale[0]), float(robot.gripper_scale[1])]}}
        return spec

    def _cam_index(self) -> dict[str, int]:
        cm = self.env.camera_manager
        return {n: i for i, n in enumerate(cm.camera_names[0])}

    def camera_info(self, cameras=None) -> dict[str, dict]:
        """Per camera: intrinsic_cv (3x3), extrinsic_cv (world -> camera, OpenCV axes, 3x4), cam2world_gl (4x4, OpenGL
        axes: x right, y up, z back), image_size [W, H], mount (static pose or the arm link it rides on)."""
        cm, idx, out = self.env.camera_manager, self._cam_index(), {}
        for cam in (cameras or CAMERAS):
            i = idx[cam]
            K = np.asarray(cm.get_camera_intrinsics(i, 0), dtype=np.float64)
            T_gl = np.asarray(cm.get_camera_extrinsics(i, 0), dtype=np.float64)
            T_cv = T_gl @ np.diag([1.0, -1.0, -1.0, 1.0])
            E = np.linalg.inv(T_cv)[:3]
            mount = ({"type": "static", "cam2world_gl": T_gl.round(6).tolist()} if cam == "cam_head" else
                     {"type": "link", "link": ("left" if "left" in cam else "right") + "_link6"})
            out[cam] = {"intrinsic_cv": K.round(6).tolist(), "extrinsic_cv": E.round(6).tolist(), "cam2world_gl": T_gl.round(6).tolist(),
                        "image_size": [640, 480], "mount": mount}
        return out

    # ---- kinematics: a numpy model of each X5 arm from its URDF (no physics, no simulated time)
    def _kin(self) -> dict:
        if getattr(self, "_kin_models", None) is None:
            self._kin_models = {}
            for arm in ARMS:
                robot, key = self._arm(arm)
                root = _np(key.data.root_pose_w)[0]
                self._kin_models[arm] = X5Model(robot.urdf_path, root[:3], root[3:7])
        return self._kin_models

    def fk(self, q12) -> dict[str, list]:
        """Poses ([x y z qw qx qy qz], env frame) of every link of both arms for joint angles q12 (left 1..6, right 1..6)."""
        q12 = np.asarray(q12, dtype=np.float64).reshape(12)
        out = {}
        for k, arm in enumerate(ARMS):
            for link, T in self._kin()[arm].fk(q12[6 * k:6 * k + 6]).items():
                out[f"{arm}_{link}"] = pose7(T)
        return out

    def ik(self, targets: dict, seed=None) -> dict:
        """targets: {"left_link6": pose7, "right_link6": pose7} (either or both) -> {"ok", "q" (12), "error"}."""
        q = np.asarray(seed if seed is not None else np.concatenate([self._targets[ARM_SLICE[a]] for a in ARMS]), dtype=np.float64).copy()
        ok, err = True, {}
        for k, arm in enumerate(ARMS):
            t = targets.get(f"{arm}_link6")
            if t is None:
                continue
            sol, e = self._kin()[arm].ik(np.asarray(t, dtype=np.float64), q[6 * k:6 * k + 6])
            q[6 * k:6 * k + 6] = sol
            err[arm] = e
            ok = ok and e["pos_m"] < 1e-3 and e["rot_rad"] < 1e-2
        return {"ok": bool(ok), "q": q.round(6).tolist(), "error": err}

    def kinematics(self, req: dict) -> dict:
        """Stateless FK / IK on the numpy arm models (never reads or changes the simulator):
          {"op": "fk", "q": [12] (left joint1..6, right joint1..6), "links": [...]?} -> {"ok", "op", "frame", "poses": {link: pose7}}
          {"op": "ik", "targets": {"left_link6"|"right_link6": pose7}, "seed": [12]?} -> {"ok", "op", "frame", "q": [12], "error"}"""
        if not isinstance(req, dict):
            raise ValueError("the request must be a dict")
        if req.get("op") == "fk":
            q = np.asarray(req.get("q"), dtype=np.float64).reshape(-1)
            if q.size != 12 or not np.all(np.isfinite(q)):
                raise ValueError("q must be 12 finite numbers")
            poses = self.fk(q)
            links = req.get("links") or list(poses)
            if any(k not in poses for k in links):
                raise ValueError(f"links must be names from {list(poses)}")
            return {"ok": True, "op": "fk", "frame": "world", "poses": {k: poses[k] for k in links}}
        if req.get("op") == "ik":
            tg = req.get("targets")
            if not isinstance(tg, dict) or not tg or any(k not in ("left_link6", "right_link6") for k in tg):
                raise ValueError("targets must map left_link6 / right_link6 to poses [x y z qw qx qy qz]")
            for k, v in tg.items():
                v = np.asarray(v, dtype=np.float64).reshape(-1)
                if v.size != 7 or not np.all(np.isfinite(v)) or np.linalg.norm(v[3:]) < 1e-6:
                    raise ValueError(f"targets[{k}] must be [x, y, z, qw, qx, qy, qz] with a non-zero quaternion")
            seed = req.get("seed")
            if seed is not None:
                seed = np.asarray(seed, dtype=np.float64).reshape(-1)
                if seed.size != 12 or not np.all(np.isfinite(seed)):
                    raise ValueError("seed must be 12 finite numbers")
            r = self.ik(tg, seed=seed)
            return {"ok": r["ok"], "op": "ik", "frame": "world", "q": r["q"],
                    "error": {f"{a}_link6": e for a, e in r["error"].items()}}
        raise ValueError("op must be 'fk' or 'ik'")

    def kinematics_check(self) -> dict:
        """The arm models against the simulator: FK of the measured joints vs the measured link6 poses (m, rad)."""
        P = self.proprio()
        q12 = [P["joint_pos"][i] for i in list(range(0, 6)) + list(range(7, 13))]
        poses = self.fk(q12)
        out = {}
        for k, arm in enumerate(ARMS):
            meas = np.asarray(P["tcp_pose"][7 * k:7 * k + 7]); mod = np.asarray(poses[f"{arm}_link6"])
            d = abs(float(np.dot(meas[3:] / np.linalg.norm(meas[3:]), mod[3:] / np.linalg.norm(mod[3:]))))
            out[arm] = {"link6_pos_err_m": round(float(np.linalg.norm(meas[:3] - mod[:3])), 6),
                        "link6_rot_err_rad": round(float(2 * np.arccos(min(1.0, d))), 6)}
        return out

    # ---- privileged scene state
    def labels(self) -> list[str]:
        out = []
        for kind in ("Rigid", "Articulation", "Garment", "Fluid", "Geometry", "Clutter"):
            for _cat, items in (self.layout_data.get(kind) or {}).items():
                for it in items if isinstance(items, list) else []:
                    if isinstance(it, dict) and it.get("label"):
                        out.append(str(it["label"]))
        return out

    def objects(self) -> dict[str, dict]:
        lm, out = self.env.scene_manager.layout_manager, {}
        for label in self.labels():
            try:
                pos, rot = lm.get_instance_pose(0, label=label)
                d = {"position": _np(pos).reshape(-1)[:3].round(5).tolist(),
                     "orientation_wxyz": _np(rot).reshape(-1)[:4].round(5).tolist()}
                try:
                    inst = lm.get_instance_name(0, label)
                    d["bbox_corners"] = _np(lm.get_instance_bbox_vertices(inst, 0)).round(5).tolist()
                except Exception:  # noqa: BLE001
                    pass
                out[label] = d
            except Exception as exc:  # noqa: BLE001
                out[label] = {"error": repr(exc)[:200]}
        return out

    def instruction(self) -> str:
        try:
            return str(self.env.obs_manager.instruction[0])
        except Exception:  # noqa: BLE001
            return ""

    # ---- helpers that produce actions (every row goes through step(), so it is recorded)
    def primitives(self) -> dict[str, Callable]:
        s = self

        def hold(n: int = 1) -> bool:
            """Keep the current targets for n control steps."""
            for _ in range(int(n)):
                if s.step(s.hold_action()):
                    return True
            return False

        def move_joints(left=None, right=None, steps: int = 25) -> bool:
            """Move the arms' joint targets linearly to `left` / `right` (6 joint angles each, rad) over `steps` actions."""
            start = s.hold_action()
            goal = start.copy()
            if left is not None:
                goal[ARM_SLICE["left"]] = np.asarray(left, dtype=np.float64)
            if right is not None:
                goal[ARM_SLICE["right"]] = np.asarray(right, dtype=np.float64)
            for k in range(1, int(steps) + 1):
                if s.step(start + (goal - start) * k / steps):
                    return True
            return False

        def set_gripper(arm: str, value: float, steps: int = 10) -> bool:
            """Ramp one gripper's normalised command to `value` (0..1) over `steps` actions."""
            start = s.hold_action()
            for k in range(1, int(steps) + 1):
                a = s.hold_action()
                a[GRIP_INDEX[arm]] = start[GRIP_INDEX[arm]] + (float(value) - start[GRIP_INDEX[arm]]) * k / steps
                if s.step(a):
                    return True
            return False

        def ik(arm: str, pose7) -> np.ndarray | None:
            """RoboDojo's IK (cuRobo) for one arm: a tool pose [x y z qw qx qy qz] in the world frame -> 6 joint angles, or
            None. Stateless: no physics runs."""
            rm = s.env.robot_manager
            robot = next(r for r in rm.robot_list if r.type == "target" and r.arm_name.startswith(arm))
            res = rm.solve_ik(target_pose=list(map(float, pose7)), env_idx=0, robot=robot)
            return np.asarray(res["joint_value"], dtype=np.float64)[:6] if res.get("status") == "Success" else None

        def move_ee(arm: str, pose7, steps: int = 25) -> bool:
            """IK to `pose7` for one arm, then move_joints there."""
            q = ik(arm, pose7)
            if q is None:
                raise PrimitiveError(f"no IK solution for {arm} at {list(pose7)}")
            return move_joints(**{arm: q}, steps=steps)

        return {"hold": hold, "move_joints": move_joints, "set_gripper": set_gripper, "ik": ik, "move_ee": move_ee}

    # ---- video
    def start_video(self, path: str | Path, fps: int = 12, every: int = 2, camera: str = "cam_head") -> None:
        import imageio
        self._video = {"w": imageio.get_writer(str(path), fps=fps, codec="libx264", quality=7, macro_block_size=8),
                       "every": int(every), "camera": camera, "path": str(path)}
        self._video_add()

    def _video_add(self) -> None:
        """One frame. Filming never decides an episode: a frame that cannot be rendered or written stops the video (reported
        by stop_video() returning None, `video_ok` false in the replay CLI) and the episode carries on."""
        try:
            self._video["w"].append_data(self.render_frame(self._video["camera"]))
        except Exception as exc:  # noqa: BLE001
            print(f"[rcb_robodojo] video stopped: {exc!r}"[:300], file=sys.stderr, flush=True)
            self._video["failed"] = True

    def stop_video(self) -> str | None:
        """Close the video; its path, or None when it failed (nothing was being filmed, a frame or the encoder failed)."""
        if self._video is None:
            return None
        v, self._video = self._video, None
        try:
            v["w"].close()
        except Exception as exc:  # noqa: BLE001
            print(f"[rcb_robodojo] video not written: {exc!r}"[:300], file=sys.stderr, flush=True)
            return None
        return None if v.get("failed") else v["path"]

    def render_video(self, actions: np.ndarray, path: str | Path, every: int = 2, fps: int = 12) -> dict[str, Any]:
        """Reset, step `actions` and film the head camera. The episode's result never depends on the filming: a video that
        cannot be started, filmed or written gives `video_ok` false and the result stands."""
        self.reset()
        try:
            self.start_video(path, fps=fps, every=every)
        except Exception as exc:  # noqa: BLE001
            print(f"[rcb_robodojo] video not started: {exc!r}"[:300], file=sys.stderr, flush=True)
            self._video = None
        started = self._video is not None
        for a in np.asarray(actions, dtype=np.float64):
            if self.step(a):
                break
        video_ok = started and self.stop_video() is not None
        return {"video": str(path), "video_ok": video_ok, **self.status()}

    def _log_end(self) -> None:
        if not self._end_logged:
            self._end_logged = True
            _slog("session_end", task=self.task, resets=self._resets)

    def close(self) -> None:
        """End the process's simulator. Isaac's app.close() can hang at shutdown, so this flushes and exits the process."""
        self._log_end()
        sys.stdout.flush(); sys.stderr.flush()
        os._exit(0)


def _load_traj(path: str) -> dict[str, Any]:
    """`task` and `actions` of a trajectory file, the two entries a replay reads. Any other entry is never loaded: a file
    with an extra entry numpy refuses without pickle (a dict saved as `meta`, an object array) or with a large padding
    array is still the same trajectory, and must be replayed, not end the replay process without a result."""
    with np.load(path, allow_pickle=False) as d:
        return {"task": str(d["task"]), "actions": np.asarray(d["actions"])}


def cmd_make_instance(a) -> None:
    """Freeze one of RoboDojo's evaluation layouts: Assets/Eval_Layout/RoboDojo/arx_x5/<seed>/<task>_<layout>.json."""
    physx = {}
    for kv in a.physx or []:
        k, v = kv.split("=", 1)
        physx[k] = json.loads(v)
    s = Session(a.task, seed=a.seed, layout=a.layout, physx=physx)
    src = s.env.seed_manager.seed_info[a.layout]["scene_layout"]
    raw = Path(src).read_bytes()
    out = {"task": a.task, "seed": a.seed, "layout_index": a.layout, "layout_file": os.path.relpath(src, ROBODOJO_ROOT),
           "layout_sha256": hashlib.sha256(raw).hexdigest(), "layout": json.loads(raw), "state_sha": s.instance_sha,
           "step_lim": s.robodojo_step_lim, "control_hz": CONTROL_HZ, "action_dim": ACTION_DIM, "instruction": s.instruction(),
           "labels": s.labels(), "objects": s.objects(), "start_action": s.hold_action().round(6).tolist(), "physics": physx}
    Path(a.out).write_text(json.dumps(out, indent=1))
    print("\n" + json.dumps({k: out[k] for k in ("task", "seed", "layout_index", "layout_sha256", "state_sha", "step_lim", "instruction")}),
          flush=True)
    s._log_end()      # Isaac's app.close() can hang at shutdown: main() hard-exits once the output is flushed


def cmd_run_actions(a) -> None:
    s = Session(a.task, instance=a.instance, strict=True)
    acts = np.load(a.actions).astype(np.float64)
    t0 = time.time()
    s.record_start()
    for row in acts:
        if s.step(row):
            break
    rec = s.record_stop()
    st = s.status()
    s.save_trajectory(rec, a.out, meta={"source": a.source, "wall_s": round(time.time() - t0, 1)})
    print("\n" + json.dumps({"traj": a.out, "n_actions": int(len(rec)), **st, "wall_s": round(time.time() - t0, 1)}), flush=True)
    s._log_end()      # Isaac's app.close() can hang at shutdown: main() hard-exits once the output is flushed


def cmd_replay(a) -> None:
    traj = _load_traj(a.traj)
    if str(traj.get("task")) != a.task:
        print(json.dumps({"error": f"trajectory task {traj.get('task')} != {a.task}"}), flush=True)
        sys.exit(2)
    s = Session(a.task, instance=a.instance, strict=a.strict)
    acts = np.asarray(traj["actions"], dtype=np.float64)
    t0 = time.time()
    video_ok = None
    if a.video:
        st = s.render_video(acts, a.video)
        st.pop("video", None); video_ok = st.pop("video_ok", None)
    else:
        for row in acts:
            if s.step(row):
                break
        st = s.status()
    st["sim_steps"] = st["actions"]
    out = {"n_actions": int(len(acts)), "instance_sha": s.instance_sha, "instance_exact": s.instance_exact,
           "instance_matches": s.instance_exact, "replays": [st], "all_success": bool(st["success"]),
           "wall_s": round(time.time() - t0, 1), "video": a.video, "video_ok": video_ok}
    print("\n" + json.dumps(out), flush=True)
    s._log_end()      # Isaac's app.close() can hang at shutdown: main() hard-exits once the output is flushed


def main() -> None:
    p = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    sub = p.add_subparsers(dest="cmd", required=True)
    q = sub.add_parser("make-instance"); q.add_argument("--task", required=True); q.add_argument("--seed", type=int, default=0)
    q.add_argument("--layout", type=int, default=0); q.add_argument("--out", required=True)
    q.add_argument("--physx", action="append", help="key=json-value on top of RoboDojo's PhysX settings, recorded in the instance "
                                                    "(e.g. enable_enhanced_determinism=true)")
    q.set_defaults(fn=cmd_make_instance)
    q = sub.add_parser("run-actions"); q.add_argument("--task", required=True); q.add_argument("--instance", required=True)
    q.add_argument("--actions", required=True); q.add_argument("--out", required=True); q.add_argument("--source", default="pre-recorded actions")
    q.set_defaults(fn=cmd_run_actions)
    q = sub.add_parser("replay"); q.add_argument("--task", required=True); q.add_argument("--instance", required=True)
    q.add_argument("--traj", required=True); q.add_argument("--video", default=None); q.add_argument("--strict", action="store_true")
    q.set_defaults(fn=cmd_replay)
    a = p.parse_args()
    a.fn(a)
    sys.stdout.flush(); sys.stderr.flush()
    os._exit(0)


if __name__ == "__main__":
    main()
