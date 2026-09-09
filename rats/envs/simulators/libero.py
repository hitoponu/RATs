from __future__ import annotations

import logging
import os
import sys
from typing import Any, Literal

import numpy as np
import viser
import viser.extras
import viser.transforms as vtf
from robot_descriptions.loaders.yourdfpy import load_robot_description
from viser.extras import ViserUrdf

from rats.envs.base import BaseEnv
from rats.integrations.libero import load_libero_task
from rats.utils.camera_utils import obs_get_rgb
from rats.utils.depth_utils import depth_color_to_pointcloud

logger = logging.getLogger("rats.envs.libero")

here = os.path.dirname(os.path.abspath(__file__))
vendor_root = os.path.normpath(os.path.join(here, "..", "third_party", "LIBERO"))
if os.path.isdir(vendor_root) and vendor_root not in sys.path:
    sys.path.append(vendor_root)
# try:
from libero import benchmark  # type: ignore[import-not-found]
from libero.envs import OffScreenRenderEnv  # type: ignore[import-not-found]
from libero.utils import get_libero_path  # type: ignore[import-not-found]
# except Exception as e:  # pragma: no cover - optional dependency
#     raise ModuleNotFoundError(
#         "LIBERO not available; add submodule or run `uv sync --extra libero`."
#     ) from e


def get_real_depth_map(sim, depth_map):
    """Convert MuJoCo normalized depth values to metric distances."""
    assert np.all(depth_map >= 0.0) and np.all(depth_map <= 1.0)
    extent = sim.model.stat.extent
    far = sim.model.vis.map.zfar * extent
    near = sim.model.vis.map.znear * extent
    return near / (1.0 - depth_map * (1.0 - near / far))


class FrankaLiberoEnv(BaseEnv):
    """Franka Libero environment.

    This environment wraps LIBERO's Franka environment.
    """

    def __init__(
        self,
        suite_name: str,
        task_id: int,
        privileged: bool = True,
        max_steps: int = 4000,
        seed: int | None = None,
        enable_render: bool = False,
        control_freq: int = 20,
        viser_debug: bool = False,
    ) -> None:
        super().__init__()
        self.privileged = privileged
        self.max_steps = max_steps
        self.seed = seed
        self.enable_render = enable_render  # TODO(haoru): let this arg affect env
        self.segmentation_level = "instance"
        self._render_width = 800
        self._render_height = 512

        self.handle = load_libero_task(
            suite_name=suite_name,
            task_id=task_id,
            cam_w=self._render_width,
            cam_h=self._render_height,
            controller="JOINT_POSITION",
            horizon=max_steps,
            control_freq=control_freq,
        )

        # State tracking
        self._step_count = 0
        self._sim_step_count = 0
        self._control_freq = control_freq
        self._rng = np.random.default_rng(self.seed)
        self._current_obs = None
        self._current_info = None
        self._current_reward = None
        self._current_done = None

        # Video capture
        self._record_frames = False
        self._frame_buffer: list[np.ndarray] = []
        self._wrist_frame_buffer: list[np.ndarray] = []
        self._record_wrist_camera = False
        self._wrist_camera_name = "robot0_eye_in_hand"
        self._subsample_rate = 4
        self._full_viser_rate = 20  # Full scene update every 20 steps (cameras + pointcloud)

        # Robot link indices for transforms
        self.gripper_metric_length = 0.04
        self.base_link_idx = self.handle.env.sim.model.body_name2id("robot0_base")
        self.gripper_link_idx = self.handle.env.sim.model.body_name2id("gripper0_eef")

        self.base_link_wxyz_xyz = np.concatenate(
            [
                self.handle.env.sim.data.xquat[self.base_link_idx],
                self.handle.env.sim.data.xpos[self.base_link_idx],
            ]
        )

        self.gripper_link_wxyz_xyz = np.concatenate(
            [
                self.handle.env.sim.data.xquat[self.gripper_link_idx],
                self.handle.env.sim.data.xpos[self.gripper_link_idx],
            ]
        )

        # Precompute fast joint qpos addresses for Panda (avoid heavy _get_observations in tight loops)
        joint_names = [f"robot0_joint{i}" for i in range(1, 8)]
        self._panda_joint_qpos_addrs: list[int] = []
        for jn in joint_names:
            addr = self.handle.env.sim.model.get_joint_qpos_addr(jn)
            # All Panda joints are 1-DoF; addr should be an int
            if isinstance(addr, tuple):
                addr = addr[0]
            self._panda_joint_qpos_addrs.append(int(addr))

        self.home_joint_position: np.ndarray | None = None

        # Viser debugging
        self.viser_debug = viser_debug
        if viser_debug:
            self.viser_server = viser.ViserServer()

            self.pyroki_ee_frame_handle = None
            self.mjcf_ee_frame_handle = None
            self.mjcf_gripper_frame_handle = None
            self.urdf_vis = None
            self.viser_img_handle = None
            self.image_frustum_handle = None
            self.urdf = load_robot_description("panda_description")
            self.urdf_vis = ViserUrdf(self.viser_server, urdf_or_path=self.urdf, load_meshes=True)
            self._viser_init_check()

            self.cube_points = None
            self.cube_color = None
            self.cube_center = None
            self.cube_rot = None
            self.grasp_sample = None
            self.grasp_scores = None
            self.grasp_contact_pts = None
            self.grasp_frame_position = None
            self.grasp_frame_orientation = None
        else:
            self.viser_server = None

        self.reset()

    def reset(
        self, *, seed: int | None = None, options: dict[str, Any] | None = None
    ) -> tuple[dict[str, Any], dict[str, Any]]:
        if seed is not None:
            # NOTE: currently not used
            self._rng = np.random.default_rng(seed)

        # We call handle.reset, but then we might want to override the init state
        libero_obs, libero_info = self.handle.reset(seed=seed)
        
        # Override the init state based on the seed (which corresponds to trial ID)
        if self.handle.init_states is not None and len(self.handle.init_states) > 0:
            if seed is not None:
                # Assuming seed is the trial number (1-based)
                state_idx = (seed - 1) % len(self.handle.init_states)
                self.handle.env.set_init_state(self.handle.init_states[state_idx])
                # Reset simulation again to apply the new init state
                libero_obs = self.handle.env.reset()
                libero_info = {}

        self._current_obs = libero_obs
        self._current_info = libero_info
        self._current_done = False  # Must clear before settling loop (_step_once checks this)

        self._step_count = 0
        self._sim_step_count = 0

        self._current_joints = self.handle.env.sim.data.qpos[:7].copy()
        self.home_joint_position = np.array(libero_obs["robot0_joint_pos"], dtype=np.float64)
        self._gripper_fraction = 1.0

        # Post-reset settling: let physics stabilize (objects drop, joints settle).
        # 10 steps suffice — joints converge by step ~5.
        # Baselines must be taken AFTER settling: objects drop a few millimetres
        # onto their supports during these steps, and a baseline captured
        # mid-drop makes the settle itself look like a lift.
        self._pick_bodies = {}
        self._pick_baseline_z = {}
        self._pick_events = []

        for _ in range(10):
            self._step_once()

        self._init_pick_tracker()

        obs = self.get_observation()
        self.gripper_link_wxyz_xyz = np.concatenate(
            [
                self.handle.env.sim.data.xquat[self.gripper_link_idx],
                self.handle.env.sim.data.xpos[self.gripper_link_idx],
            ]
        )

        # Update viser immediately so the 3D view reflects the reset state
        if self.viser_debug:
            self._update_viser_server()

        info = {"task_prompt": self.handle.task_language}
        return obs, info

    def step(self, action: Any) -> tuple[dict[str, Any], float, bool, bool, dict[str, Any]]:
        """Low-level step - not typically called directly in code execution mode."""
        self._step_count += 1
        # This is a fallback; normally FrankaControlApi methods are used
        obs = self.get_observation()
        reward = self.compute_reward()
        terminated = False
        truncated = self._step_count >= self.max_steps
        info: dict[str, Any] = {}
        return obs, reward, terminated, truncated, info

    # ----------------------- FrankaControlApi Interface -----------------------

    def move_to_joints_blocking(
        self, joints: np.ndarray, *, tolerance: float = 0.01, max_steps: int = 120
    ) -> None:
        """Move to target joint positions using LIBERO's controller.

        Args:
            joints: (7,) target joint positions in radians
            tolerance: Position tolerance for convergence
            max_steps: Maximum simulation steps to reach target
        """
        target = np.asarray(joints, dtype=np.float64).reshape(7)
        self._current_joints = target

        steps = 0
        while steps < max_steps:
            # Get current joint positions
            current = np.array(
                self.handle.env.sim.data.qpos[self._panda_joint_qpos_addrs], dtype=np.float64
            )

            # Check convergence (but step at least once)
            error = np.linalg.norm(current - target)
            if error < tolerance and steps > 0:
                break

            # Build LIBERO action: [7 joint positions + 1 gripper control]
            delta = (target - current) * self._control_freq
            action = np.concatenate([delta, [self._gripper_fraction]])
            # Map gripper: 1.0 (open) -> -1.0, 0.0 (closed) -> 1.0
            action[-1] = 1.0 - action[-1] * 2.0

            # Step the environment
            self._current_obs, self._current_reward, self._current_done, self._current_info = (
                self.handle.step(action)
            )
            self._sim_step_count += 1

            self.gripper_link_wxyz_xyz = np.concatenate(
                [
                    self.handle.env.sim.data.xquat[self.gripper_link_idx],
                    self.handle.env.sim.data.xpos[self.gripper_link_idx],
                ]
            )

            if self.viser_debug and self._sim_step_count % self._subsample_rate == 0:
                if self._sim_step_count % self._full_viser_rate == 0:
                    self._update_viser_server()  # Full update with pointcloud
                else:
                    self._update_viser_robot_only()  # Fast robot-only

            if self._record_frames and self._sim_step_count % self._subsample_rate == 0:
                self._record_frame()

            # Stop if episode terminated (max steps or task done)
            if self._current_done:
                break

            steps += 1

    def _set_gripper(self, fraction: float) -> None:
        """Set gripper opening fraction.

        Args:
            fraction: 0.0 (closed) to 1.0 (open)
        """
        self._gripper_fraction = float(np.clip(fraction, 0.0, 1.0))

    def _step_once(self) -> None:
        """Execute one simulation step with current control state."""
        # Don't step a terminated episode
        if self._current_done:
            return

        # Build action from current state
        action = np.concatenate([np.zeros_like(self._current_joints), [self._gripper_fraction]])
        # Map gripper: 1.0 (open) -> -1.0, 0.0 (closed) -> 1.0
        action[-1] = 1.0 - action[-1] * 2.0

        self._current_obs, self._current_reward, self._current_done, self._current_info = (
            self.handle.step(action)
        )
        self._sim_step_count += 1

        self.gripper_link_wxyz_xyz = np.concatenate(
            [
                self.handle.env.sim.data.xquat[self.gripper_link_idx],
                self.handle.env.sim.data.xpos[self.gripper_link_idx],
            ]
        )

        if self.viser_debug and self._sim_step_count % self._subsample_rate == 0:
            self._update_viser_robot_only()

        if self._record_frames and self._sim_step_count % self._subsample_rate == 0:
            self._record_frame()

        self._track_lift()

    def _get_object_pose(self, obj_name: str) -> tuple[np.ndarray, np.ndarray]:
        """Get the pose of an object in the environment as a position (3,) and WXYZ quaternion (4,).

        Args:
            obj_name: The name of the object to get the pose of, in underscore separated lowercase words.

        Returns:
            position: (3,) XYZ in meters.
            quaternion_wxyz: (4,) WXYZ unit quaternion.
        """
        base_link_wxyz_xyz = np.concatenate(
            [
                self.handle.env.sim.data.xquat[self.base_link_idx],
                self.handle.env.sim.data.xpos[self.base_link_idx],
            ]
        )
        obj_pos_key = f"{obj_name}_1_pos"
        obj_quat_key = f"{obj_name}_1_quat"

        # Try exact match first, then fuzzy match on partial name
        if obj_pos_key not in self._current_obs:
            # Find all object names in the observation
            available_obs = sorted(set(
                k.rsplit("_1_pos", 1)[0]
                for k in self._current_obs
                if k.endswith("_1_pos") and not k.startswith("robot")
            ))
            # Try fuzzy match in obs keys
            query = obj_name.replace(" ", "_").lower()
            matches = [a for a in available_obs if query in a or a in query]
            if len(matches) == 1:
                obj_pos_key = f"{matches[0]}_1_pos"
                obj_quat_key = f"{matches[0]}_1_quat"
            else:
                # Fallback: search MuJoCo sim bodies (for fixed objects like stove, cabinet)
                sim = self.handle.env.sim
                body_names = [sim.model.body_id2name(i) for i in range(sim.model.nbody)]
                body_matches = [b for b in body_names if b and query in b.lower()]
                if body_matches:
                    # Prefer _main body, else first match
                    body_name = next((b for b in body_matches if b.endswith("_main")), body_matches[0])
                    body_id = sim.model.body_name2id(body_name)
                    obj_pos = sim.data.xpos[body_id]
                    obj_quat_xyzw = sim.data.xquat[body_id]  # MuJoCo returns wxyz
                    # MuJoCo xquat is already wxyz
                    obj_quat_wxyz = np.array(obj_quat_xyzw, dtype=np.float64)
                    obj_world = vtf.SE3(wxyz_xyz=np.concatenate([obj_quat_wxyz, obj_pos]))
                    base_transform = vtf.SE3(wxyz_xyz=base_link_wxyz_xyz).inverse()
                    obj_robot_base = base_transform @ obj_world
                    return obj_robot_base.translation(), obj_robot_base.rotation().wxyz

                # List everything available
                available_bodies = sorted(set(
                    b for b in body_names
                    if b and not any(x in b for x in ["robot", "world", "gripper", "mount", "base"])
                    and "_main" in b
                ))
                available_bodies = [b.replace("_1_main", "").replace("_main", "") for b in available_bodies]
                raise KeyError(
                    f"Object '{obj_name}' not found. Available objects: {available_obs + available_bodies}"
                )

        obj_pos = self._current_obs[obj_pos_key]
        obj_quat_xyzw = self._current_obs[obj_quat_key]
        obj_quat_wxyz = np.array(
            [obj_quat_xyzw[3], obj_quat_xyzw[0], obj_quat_xyzw[1], obj_quat_xyzw[2]],
            dtype=np.float64,
        )
        obj_world = vtf.SE3(wxyz_xyz=np.concatenate([obj_quat_wxyz, obj_pos]))

        base_transform = vtf.SE3(wxyz_xyz=base_link_wxyz_xyz).inverse()
        obj_robot_base = base_transform @ obj_world
        return obj_robot_base.translation(), obj_robot_base.rotation().wxyz

    def _get_all_object_poses(self) -> dict[str, tuple[np.ndarray, np.ndarray]]:
        """Get poses for all objects in the scene.

        Returns:
            Dictionary mapping object name to (position (3,), quaternion_wxyz (4,)).
        """
        base_link_wxyz_xyz = np.concatenate(
            [
                self.handle.env.sim.data.xquat[self.base_link_idx],
                self.handle.env.sim.data.xpos[self.base_link_idx],
            ]
        )
        base_transform = vtf.SE3(wxyz_xyz=base_link_wxyz_xyz).inverse()

        poses: dict[str, tuple[np.ndarray, np.ndarray]] = {}

        # Movable objects from observation keys
        movable_names = sorted(set(
            k.rsplit("_1_pos", 1)[0]
            for k in self._current_obs
            if k.endswith("_1_pos") and not k.startswith("robot")
        ))
        for name in movable_names:
            obj_pos = self._current_obs[f"{name}_1_pos"]
            obj_quat_xyzw = self._current_obs[f"{name}_1_quat"]
            obj_quat_wxyz = np.array(
                [obj_quat_xyzw[3], obj_quat_xyzw[0], obj_quat_xyzw[1], obj_quat_xyzw[2]],
                dtype=np.float64,
            )
            obj_world = vtf.SE3(wxyz_xyz=np.concatenate([obj_quat_wxyz, obj_pos]))
            obj_robot_base = base_transform @ obj_world
            poses[name] = (obj_robot_base.translation(), obj_robot_base.rotation().wxyz)

        # Fixed objects from MuJoCo bodies
        sim = self.handle.env.sim
        body_names = [sim.model.body_id2name(i) for i in range(sim.model.nbody)]
        for body_name in body_names:
            if (
                not body_name
                or any(x in body_name for x in ["robot", "world", "gripper", "mount", "base"])
                or "_main" not in body_name
            ):
                continue
            clean_name = body_name.replace("_1_main", "").replace("_main", "")
            if clean_name in poses:
                continue
            body_id = sim.model.body_name2id(body_name)
            obj_pos = sim.data.xpos[body_id]
            obj_quat_wxyz = np.array(sim.data.xquat[body_id], dtype=np.float64)
            obj_world = vtf.SE3(wxyz_xyz=np.concatenate([obj_quat_wxyz, obj_pos]))
            obj_robot_base = base_transform @ obj_world
            poses[clean_name] = (obj_robot_base.translation(), obj_robot_base.rotation().wxyz)

        return poses

    def compute_reward(self) -> float:
        return self._current_reward

    def get_observation(self) -> dict[str, Any]:
        """Get observation in FrankaLiberoEnv format."""
        obs = {}

        camera_names = [
            "agentview",
            "robot0_eye_in_hand",
        ]

        for camera_name in camera_names:
            if camera_name not in obs:
                obs[camera_name] = {}

            cam_world_wxyz_xyz = np.concatenate(
                [
                    vtf.SO3.from_matrix(self.handle.env.sim.data.get_camera_xmat(camera_name)).wxyz,
                    self.handle.env.sim.data.get_camera_xpos(camera_name),
                ]
            )
            cam_robot_tf = (
                (
                    vtf.SE3(wxyz_xyz=self.base_link_wxyz_xyz).inverse()
                    @ vtf.SE3(wxyz_xyz=cam_world_wxyz_xyz)
                )
                @ vtf.SE3.from_rotation_and_translation(
                    rotation=vtf.SO3.from_rpy_radians(0.0, np.pi, 0.0),
                    translation=np.array([0, 0, 0]),
                )
                @ vtf.SE3.from_rotation_and_translation(
                    rotation=vtf.SO3.from_rpy_radians(0.0, 0.0, np.pi),
                    translation=np.array([0, 0, 0]),
                )
            )
            obs[camera_name]["pose"] = np.concatenate(
                [
                    cam_robot_tf.translation(),
                    cam_robot_tf.rotation().wxyz,
                ]
            )
            obs[camera_name]["pose_mat"] = cam_robot_tf.as_matrix()

            cam_id = self.handle.env.sim.model.camera_name2id(camera_name)
            fovy = self.handle.env.sim.model.cam_fovy[cam_id]
            f = 0.5 * self._render_height / np.tan(fovy * np.pi / 360.0)

            K = np.array(
                [[f, 0, 0.5 * self._render_width], [0, f, 0.5 * self._render_height], [0, 0, 1]]
            )
            obs[camera_name]["intrinsics"] = K

            obs[camera_name]["images"] = {}
            if camera_name + "_image" in self._current_obs:
                obs[camera_name]["images"]["rgb"] = self._current_obs[camera_name + "_image"][::-1]
            if camera_name + "_depth" in self._current_obs:
                depth_metric = get_real_depth_map(
                    self.handle.env.sim, self._current_obs[camera_name + "_depth"][::-1]
                )
                obs[camera_name]["images"]["depth"] = depth_metric
            if camera_name + "_segmentation_" + self.segmentation_level in self._current_obs:
                obs[camera_name]["images"]["segmentation"] = self._current_obs[
                    camera_name + "_segmentation_" + self.segmentation_level
                ][::-1]

        gripper_robot_base = (
            vtf.SE3(wxyz_xyz=self.base_link_wxyz_xyz).inverse()
            @ vtf.SE3(wxyz_xyz=self.gripper_link_wxyz_xyz)
            @ vtf.SE3.from_rotation_and_translation(
                rotation=vtf.SO3.from_rpy_radians(0.0, 0.0, np.pi / 2.0),
                translation=np.array([0, 0, -0.107]),
            )
        )
        obs["robot_joint_pos"] = np.concatenate(
            [
                self._current_obs["robot0_joint_pos"],
                [self._current_obs["robot0_gripper_qpos"][0] / self.gripper_metric_length],
            ]
        )
        obs["robot_cartesian_pos"] = np.concatenate(
            [
                gripper_robot_base.translation(),
                gripper_robot_base.rotation().wxyz,
                [self._current_obs["robot0_gripper_qpos"][0] / self.gripper_metric_length],
            ]
        )
        return obs

    def get_current_time_s(self) -> float:
        """Get the current time in seconds.
        Args:
            None
        Returns:
            current_time: (float) Current time in seconds.
        """
        return self._sim_step_count / self._control_freq

    def task_completed(self) -> bool:
        """Compute if the task is completed."""
        return self.handle.env.check_success()

    # --------------------- Ground-truth state record ---------------------

    # A pick is only visible while it is happening. Snapshots at code-block
    # boundaries miss it entirely: a successful pick-and-place is already
    # released by the time the block ends, and a pick whose place failed puts
    # the object back down, so "picked the wrong bowl and dropped it" and
    # "never grasped anything" produce identical before/after states. Hence a
    # tracker that runs inside the control loop.
    _PICK_LIFT_M = 0.03  # bowls are ~5 cm tall; 3 cm clears the table

    def _inner_env(self, *required: str) -> Any:
        """Walk down to the env that actually owns ``required`` attributes.

        ``self.handle.env`` is an ``OffScreenRenderEnv``/``ControlEnv``
        wrapper. It forwards only a fixed list (``sim``, ``robots``,
        ``check_success``, ...) and defines no ``__getattr__``, so
        ``obj_body_id``, ``get_object`` and ``_check_grasp`` — all owned by
        the inner ``Libero_*_Manipulation`` problem env — are simply absent
        on it. Reading them off the wrapper silently yields None, which is
        how the lift tracker and the grasp check ended up permanently
        inert (empty ``pick_events`` / ``fingerpad_contact`` on every run).
        """
        cache_key = "_inner_env_cache_" + "_".join(required)
        cached = getattr(self, cache_key, None)
        if cached is not None:
            return cached
        cur = getattr(self.handle, "env", None)
        visited: set[int] = set()
        for _ in range(8):
            if cur is None or id(cur) in visited:
                return None
            visited.add(id(cur))
            if all(getattr(cur, attr, None) is not None for attr in required):
                setattr(self, cache_key, cur)
                return cur
            cur = getattr(cur, "env", None) or getattr(cur, "unwrapped", None)
        return None

    def _fingerpad_contact(self, name: str) -> bool:
        """robosuite `_check_grasp`: BOTH fingerpad geoms touching this object.

        Note what this is not. There is no force, friction, or closure test —
        it is two contact queries. An open gripper straddling a wide bowl rim
        satisfies it while holding nothing, and so does the instant of a failed
        squeeze. It is evidence, not a verdict; pair it with a lift.
        """
        env = self._inner_env("_check_grasp", "get_object")
        if env is None:
            return False
        check_grasp = getattr(env, "_check_grasp", None)
        get_object = getattr(env, "get_object", None)
        if not (callable(check_grasp) and callable(get_object)):
            return False
        try:
            return bool(check_grasp(gripper=env.robots[0].gripper,
                                    object_geoms=get_object(name)))
        except Exception:
            return False

    def _init_pick_tracker(self) -> None:
        self._pick_bodies: dict[str, int] = {}
        self._pick_baseline_z: dict[str, float] = {}
        self._pick_events: list[dict[str, Any]] = []
        env = self._inner_env("obj_body_id")
        body_ids = getattr(env, "obj_body_id", None) if env is not None else None
        if not isinstance(body_ids, dict):
            logger.warning(
                "Pick tracker inert: no obj_body_id found under handle.env "
                "(pick_events / picked / picked_wrong will stay empty)."
            )
            return
        for name, bid in body_ids.items():
            try:
                self._pick_bodies[name] = int(bid)
                self._pick_baseline_z[name] = float(env.sim.data.body_xpos[bid][2])
            except Exception:
                self._pick_bodies.pop(name, None)

    def _track_lift(self) -> None:
        """Cheap per-step check: did any object rise while being pinched?

        Height comes straight out of ``body_xpos`` and costs nothing, so the
        expensive contact query only runs for objects that actually moved up.
        One event per object per episode — the first lift is the pick.
        """
        if not getattr(self, "_pick_bodies", None):
            return
        try:
            xpos = self.handle.env.sim.data.body_xpos
        except Exception:
            return
        seen = {e["object"] for e in self._pick_events}
        for name, bid in self._pick_bodies.items():
            if name in seen:
                continue
            try:
                z = float(xpos[bid][2])
            except Exception:
                continue
            z0 = self._pick_baseline_z.get(name, z)
            if z - z0 <= self._PICK_LIFT_M:
                continue
            if self._fingerpad_contact(name):
                self._pick_events.append({
                    "object": name, "sim_step": int(self._sim_step_count),
                    "z0": round(z0, 4), "z": round(z, 4), "dz": round(z - z0, 4),
                })

    def _predicate_env(self) -> Any:
        """Walk down to the LIBERO problem object that owns the predicate API.

        ``self.handle.env`` is an ``OffScreenRenderEnv`` wrapper, which does NOT
        expose ``parsed_problem`` / ``_eval_predicate``; the object that does is
        its ``.env`` (e.g. ``Libero_Tabletop_Manipulation``). Stopping at the
        wrapper silently yields an empty result, so unwrap until the API appears.
        """
        return self._inner_env("parsed_problem", "_eval_predicate")

    def describe_object_state(
        self, *, relations: tuple[str, ...] = ("on", "in"),
    ) -> dict[str, Any]:
        """Ground-truth object-level state: poses, support relations, what is held.

        Answers "which object was actually picked, and what was it placed on"
        without going through perception, the policy's own ``RESULT`` dict, or a
        VLM. Compare two snapshots and the relation diff *is* the answer.

        Relations are evaluated with LIBERO's own ``_eval_predicate`` over every
        ordered object pair, so ``on(a, b)`` here means exactly what it means in
        the BDDL goal that scores the task — the goal predicate is simply one
        entry of the same table. Falls back to ``ObjectState.check_ontop`` /
        ``check_contain`` when the predicate API cannot be reached.

        Cost is quadratic in object count (~10 objects -> ~90 evaluations), so
        call it at code-block boundaries, not inside the control loop.

        Returns a JSON-safe dict:
            objects   {name: {pos: [3], quat_wxyz: [4]}}
            relations [{rel, a, b}, ...]   only the pairs that hold
            grasped   [names in the gripper]
            goal      [{predicate, satisfied}, ...]
            success   bool
        """
        out: dict[str, Any] = {
            "objects": {}, "relations": [], "fingerpad_contact": [],
            "goal": [], "success": False,
            "pick_events": list(getattr(self, "_pick_events", [])),
            "picked": [], "picked_wrong": [],
            "goal_target": None, "goal_destination": None,
            "pick_only": False,
        }
        env = getattr(self.handle, "env", None)
        if env is None:
            return out
        try:
            out["success"] = bool(env.check_success())
        except Exception:
            pass

        osd = getattr(env, "object_states_dict", None)
        if not isinstance(osd, dict) or not osd:
            # Some wrappers hold the problem object one level down.
            pred_env = self._predicate_env()
            osd = getattr(pred_env, "object_states_dict", None) if pred_env else None
        if not isinstance(osd, dict):
            return out
        names = sorted(osd)

        for name in names:
            try:
                gs = osd[name].get_geom_state()
                out["objects"][name] = {
                    "pos": [float(x) for x in gs["pos"]],
                    "quat_wxyz": [float(x) for x in gs["quat"]],
                    # "site" entries are the named regions the BDDL defines
                    # (main_table_between_plate_ramekin_region, ...). They are
                    # not physical objects, and they are how the scene encodes
                    # the spatial qualifier that picks the target out of its
                    # look-alikes — worth keeping, worth distinguishing.
                    # Classify by class, not by `object_state_type`: that
                    # attribute reads "object" on SiteObjectState too, so it
                    # cannot separate the two.
                    "type": ("site" if "Site" in type(osd[name]).__name__
                             else "fixture" if getattr(osd[name], "is_fixture", False)
                             else "object"),
                }
                # Several LIBERO goals are articulation, not support —
                # `[open wooden_cabinet_1_middle_region]` cannot be explained by
                # any on/in edge, so record the joint state where it exists.
                is_open = getattr(osd[name], "is_open", None)
                if callable(is_open):
                    try:
                        out["objects"][name]["open"] = bool(is_open())
                    except Exception:
                        pass
            except Exception:
                continue

        pred_env = self._predicate_env()
        eval_pred = getattr(pred_env, "_eval_predicate", None) if pred_env else None
        # `on` comes back symmetric whenever one side is a region site — both
        # on(bowl, region) and on(region, bowl) evaluate true, because the site
        # test is containment within the region's bounds and does not care which
        # argument is the support. Keep one direction per unordered pair so the
        # relation list stays a graph rather than a doubled edge set.
        seen: set[tuple[str, str, str]] = set()
        for rel in relations:
            for a in names:
                for b in names:
                    if a == b or (rel, b, a) in seen:
                        continue
                    ok = None
                    if callable(eval_pred):
                        try:
                            ok = bool(eval_pred((rel, a, b)))
                        except Exception:
                            ok = None
                    if ok is None:  # predicate API unreachable -> ObjectState
                        meth = {"on": "check_ontop", "in": "check_contain"}.get(rel)
                        try:
                            ok = bool(getattr(osd[a], meth)(osd[b])) if meth else False
                        except Exception:
                            ok = False
                    if ok:
                        seen.add((rel, a, b))
                        a_site = out["objects"].get(a, {}).get("type") == "site"
                        b_site = out["objects"].get(b, {}).get("type") == "site"
                        # Point the edge the way a reader expects: the supported
                        # thing first, the region it rests in second. Which
                        # direction survived dedup is arbitrary for the
                        # symmetric site case, so normalise it here.
                        if a_site and not b_site:
                            a, b, a_site, b_site = b, a, b_site, a_site
                        out["relations"].append({
                            "rel": rel, "a": a, "b": b, "b_is_site": b_site,
                        })

        # Instantaneous pad contact — only meaningful for a snapshot taken
        # mid-carry. The episode-level answer is `picked`, below.
        for name in getattr(self, "_pick_bodies", {}) or names:
            if self._fingerpad_contact(name):
                out["fingerpad_contact"].append(name)

        parsed = getattr(pred_env, "parsed_problem", None) if pred_env else None
        if isinstance(parsed, dict) and callable(eval_pred):
            for state in parsed.get("goal_state", []) or []:
                desc = "[" + " ".join(str(s) for s in state) + "]"
                try:
                    sat = bool(eval_pred(state))
                except Exception:
                    sat = False
                out["goal"].append({"predicate": desc, "satisfied": sat})
                # The goal names its own target and destination, so wrong-object
                # detection needs no region-name guesswork: anything lifted that
                # is not this target was the wrong thing to lift.
                if out["goal_target"] is None and len(state) >= 3:
                    out["goal_target"] = str(state[1])
                    out["goal_destination"] = str(state[2])

        out["picked"] = sorted({e["object"] for e in out["pick_events"]})
        tgt = out["goal_target"]
        if tgt is not None:
            out["picked_wrong"] = [n for n in out["picked"] if n != tgt]
            # Lifted the right object but it is not on the destination: the pick
            # worked and the place did not. Invisible to a before/after diff
            # whenever the object was set back down near where it started.
            goal_sat = all(g["satisfied"] for g in out["goal"]) if out["goal"] else False
            out["pick_only"] = bool(tgt in out["picked"] and not goal_sat)
        return out

    # ------------------------- Video Capture -------------------------

    def enable_video_capture(
        self,
        enabled: bool = True,
        *,
        clear: bool = True,
        wrist_camera: bool = False,
    ) -> None:
        self._record_frames = enabled
        self._record_wrist_camera = wrist_camera
        if clear:
            self._frame_buffer.clear()
            self._wrist_frame_buffer.clear()
        if enabled:
            self._record_frame()

    def get_video_frames(self, *, clear: bool = False) -> list[np.ndarray]:
        frames = [frame.copy() for frame in self._frame_buffer]
        if clear:
            self._frame_buffer.clear()
        return frames

    def get_video_frame_count(self) -> int:
        return len(self._frame_buffer)

    def get_video_frames_range(self, start: int, end: int) -> list[np.ndarray]:
        return [frame.copy() for frame in self._frame_buffer[start:end]]

    def get_wrist_video_frames(self, *, clear: bool = False) -> list[np.ndarray]:
        frames = [frame.copy() for frame in self._wrist_frame_buffer]
        if clear:
            self._wrist_frame_buffer.clear()
        return frames

    def get_wrist_video_frames_range(self, start: int, end: int) -> list[np.ndarray]:
        return [frame.copy() for frame in self._wrist_frame_buffer[start:end]]

    def _record_frame(self) -> None:
        if not self._record_frames:
            return

        frame = self.handle.env.sim.render(
            camera_name="agentview",
            width=self._render_width,
            height=self._render_height,
            depth=False,
        )
        self._frame_buffer.append(frame[::-1])  # Flip vertically

        if self._record_wrist_camera:
            wrist_frame = self.handle.env.sim.render(
                camera_name=self._wrist_camera_name,
                width=self._render_width,
                height=self._render_height,
                depth=False,
            )
            self._wrist_frame_buffer.append(wrist_frame[::-1])

    def render(self, mode: str = "rgb_array") -> np.ndarray:  # type: ignore[override]
        if mode != "rgb_array":
            raise ValueError("Only rgb_array render mode is supported")
        frame = self.handle.env.sim.render(
            camera_name="agentview",
            width=self._render_width,
            height=self._render_height,
            depth=False,
        )
        return frame[::-1]

    def render_wrist(self) -> np.ndarray:
        """Render the current frame from the wrist (eye-in-hand) camera."""
        frame = self.handle.env.sim.render(
            camera_name=self._wrist_camera_name,
            width=self._render_width,
            height=self._render_height,
            depth=False,
        )
        return frame[::-1]

    # Viser debugging — lightweight robot-only update (no camera render)
    def _update_viser_robot_only(self) -> None:
        """Update only the URDF visualization — fast, no observation render."""
        if not self.viser_debug or self.viser_server is None:
            return
        self._viser_init_check()
        joints = np.array(
            self.handle.env.sim.data.qpos[self._panda_joint_qpos_addrs], dtype=np.float64
        )
        gripper_val = self._gripper_fraction * self.gripper_metric_length
        action_joint_copy = np.append(joints, gripper_val)
        self.urdf_vis.update_cfg(action_joint_copy)

    # Viser debugging — full update with camera render and pointcloud
    def _update_viser_server(self) -> None:
        obs = self.get_observation()
        if self.viser_debug:
            self._viser_init_check()

            obs_cartesian = obs["robot_cartesian_pos"][:-1]

            action_joint_copy = obs["robot_joint_pos"].copy()
            action_joint_copy[-1] *= self.gripper_metric_length

            self.urdf_vis.update_cfg(action_joint_copy)

            rbg_imgs = obs_get_rgb(obs)
            # Use agentview as the primary camera for visualization (same as API)
            camera_key = "agentview"
            # camera_key = "robot0_eye_in_hand"

            if camera_key in rbg_imgs:
                self.viser_img_handle.image = rbg_imgs[camera_key]

                if "pose" in obs[camera_key]:
                    self.image_frustum_handle.position = obs[camera_key]["pose"][:3]
                    self.image_frustum_handle.wxyz = obs[camera_key]["pose"][3:]
                    self.image_frustum_handle.image = rbg_imgs[camera_key]
                else:
                    self.image_frustum_handle.visible = False

                self.viser_server.scene.add_frame(
                    camera_key,
                    position=obs[camera_key]["pose"][:3],
                    wxyz=obs[camera_key]["pose"][3:],
                    axes_length=0.05,
                    axes_radius=0.005,
                )

            # Visualize point cloud if depth is available
            if camera_key in obs and "depth" in obs[camera_key]["images"]:
                points_camera, colors = depth_color_to_pointcloud(
                    obs[camera_key]["images"]["depth"][:, :, 0],
                    rbg_imgs[camera_key],
                    obs[camera_key]["intrinsics"],
                )

                self.viser_server.scene.add_point_cloud(
                    f"{camera_key}/point_cloud",
                    points_camera,
                    colors,
                    point_size=0.001,
                    point_shape="square",
                )

            if self.cube_center is not None and self.cube_rot is not None:
                self.viser_server.scene.add_frame(
                    f"{camera_key}/cube_frame",
                    position=self.cube_center,
                    wxyz=vtf.SO3.from_matrix(self.cube_rot).wxyz,
                    axes_length=0.05,
                    axes_radius=0.005,
                )

            if self.cube_points is not None and self.cube_color is not None:
                self.viser_server.scene.add_point_cloud(
                    f"{camera_key}/cube_point_cloud",
                    self.cube_points,
                    self.cube_color,
                    point_size=0.001,
                    point_shape="square",
                )

            if self.grasp_frame_position is not None and self.grasp_frame_orientation is not None:
                self.viser_server.scene.add_frame(
                    f"{camera_key}/grasp",
                    position=self.grasp_frame_position,
                    wxyz=self.grasp_frame_orientation,
                    axes_length=0.05,
                    axes_radius=0.0015,
                )

            if hasattr(self, "grasp_sample") and self.grasp_sample is not None:
                grasp = self.grasp_sample[np.argmax(self.grasp_scores)]

                grasp_tf = vtf.SE3.from_matrix(grasp) @ vtf.SE3.from_translation(
                    np.array([0, 0, 0.12])
                )
                self.grasp_mesh_handle = self.viser_server.scene.add_frame(
                    f"{camera_key}/grasp",
                    position=grasp_tf.wxyz_xyz[-3:],
                    wxyz=grasp_tf.wxyz_xyz[:4],
                    axes_length=0.05,
                    axes_radius=0.0015,
                )

    def update_viser_image(self, frame: np.ndarray) -> None:
        if self.viser_server is None:
            return
        self._viser_init_check()
        if self.viser_img_handle is not None:
            self.viser_img_handle.image = frame

    def _viser_init_check(self) -> None:
        if self.viser_server is None:
            return

        if self.mjcf_ee_frame_handle is None:
            self.mjcf_ee_frame_handle = self.viser_server.scene.add_frame(
                "/panda_ee_target_mjcf", axes_length=0.15, axes_radius=0.005
            )

            self.mjcf_gripper_frame_handle = self.viser_server.scene.add_frame(
                "/panda_gripper_target_mjcf", axes_length=0.15, axes_radius=0.005
            )

        if self.viser_img_handle is None:
            img_init = np.zeros((480, 640, 3), dtype=np.uint8)
            self.viser_img_handle = self.viser_server.gui.add_image(img_init, label="Mujoco render")

        if self.image_frustum_handle is None:
            # Initialize with a generic name; actual camera will be set during updates
            self.image_frustum_handle = self.viser_server.scene.add_camera_frustum(
                name="main_camera",
                position=(0, 0, 0),
                wxyz=(1, 0, 0, 0),
                fov=1.0,
                aspect=self._render_width / self._render_height,
                scale=0.05,
            )


class FrankaLiberoTask(FrankaLiberoEnv):
    """Generic LIBERO task — specify any suite and task index.

    Use this class in YAML configs to run any LIBERO-PRO task without
    writing a new Python class::

        env:
          _target_: rats.envs.simulators.libero.FrankaLiberoTask
          suite_name: libero_spatial
          task_id: 2
          privileged: true
    """

    def __init__(
        self,
        suite_name: str = "libero_10",
        task_id: int = 0,
        privileged: bool = True,
        max_steps: int = 4000,
        seed: int | None = None,
        enable_render: bool = False,
        viser_debug: bool = False,
    ) -> None:
        super().__init__(
            suite_name=suite_name,
            task_id=task_id,
            privileged=privileged,
            max_steps=max_steps,
            seed=seed,
            enable_render=enable_render,
            viser_debug=viser_debug,
        )


# Legacy convenience classes (kept for backward compatibility with existing configs)
class FrankaLiberoPickPlace(FrankaLiberoEnv):
    def __init__(self, privileged: bool = True, max_steps: int = 4000, seed: int | None = None, enable_render: bool = False, viser_debug: bool = False) -> None:
        super().__init__(suite_name="libero_10", task_id=0, privileged=privileged, max_steps=max_steps, seed=seed, enable_render=enable_render, viser_debug=viser_debug)

class FrankaLiberoOpenMicrowave(FrankaLiberoEnv):
    def __init__(self, privileged: bool = True, max_steps: int = 4000, seed: int | None = None, enable_render: bool = False, viser_debug: bool = False) -> None:
        super().__init__(suite_name="libero_90", task_id=35, privileged=privileged, max_steps=max_steps, seed=seed, enable_render=enable_render, viser_debug=viser_debug)

class FrankaLiberoPickAlphabetSoup(FrankaLiberoEnv):
    def __init__(self, privileged: bool = True, max_steps: int = 4000, seed: int | None = None, enable_render: bool = False, viser_debug: bool = False) -> None:
        super().__init__(suite_name="libero_object", task_id=0, privileged=privileged, max_steps=max_steps, seed=seed, enable_render=enable_render, viser_debug=viser_debug)


__all__ = ["FrankaLiberoEnv", "FrankaLiberoTask", "FrankaLiberoPickPlace", "FrankaLiberoOpenMicrowave", "FrankaLiberoPickAlphabetSoup"]
