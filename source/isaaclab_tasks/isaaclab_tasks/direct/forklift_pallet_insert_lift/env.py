"""Forklift Pallet Insert+Lift 环境实现（DirectRLEnv）。
by sull

本文件是任务的核心逻辑，包含：
- 任务环境类 `ForkliftPalletInsertLiftEnv`
- 观测、奖励、终止与重置逻辑
- 叉车/托盘物理修复与诊断工具

调用流程（Isaac Lab 直接环境）：
1) `_setup_scene()`：创建资产、设置物理、克隆环境
2) `_reset_idx()`：按 env_ids 重置初始状态
3) 每步循环：
   - `_pre_physics_step(actions)`  缓存动作
   - `_apply_action()`             将动作写入仿真
   - `_get_observations()`         计算观测
   - `_get_rewards()`              计算奖励
   - `_get_dones()`                判断终止/超时

坐标约定：
- 机器人朝向以 yaw（Z 轴旋转）描述
- 叉车从 -X 方向接近托盘，插入深度沿 +X 增加
"""

from __future__ import annotations

import math
import os
from pathlib import Path
import sys
from typing import Tuple

import numpy as np
import torch

import isaaclab.sim as sim_utils
from isaaclab.assets import Articulation, RigidObject
from isaaclab.envs import DirectRLEnv
from isaaclab.sensors import TiledCamera
from isaaclab.sim.spawners.from_files import spawn_ground_plane
from isaaclab.utils.math import quat_apply, quat_apply_inverse, sample_uniform

from .env_cfg import ForkliftPalletInsertLiftEnvCfg
from .hold_logic import HoldLogicConfig, compute_hold_logic


_RS_DIR = Path(__file__).resolve().parent / "rs"
if str(_RS_DIR) not in sys.path:
    sys.path.append(str(_RS_DIR))
import rs as exact_rs


def _quat_to_yaw(q: torch.Tensor) -> torch.Tensor:
    """Extract yaw from quaternion (w,x,y,z). Assumes Z-up and mainly yaw rotations."""
    w, x, y, z = q.unbind(-1)
    # yaw (z-axis rotation)
    siny_cosp = 2.0 * (w * z + x * y)
    cosy_cosp = 1.0 - 2.0 * (y * y + z * z)
    return torch.atan2(siny_cosp, cosy_cosp)


def _yaw_to_mat2(yaw: torch.Tensor) -> torch.Tensor:
    """2x2 rotation matrix for yaw (world->robot frame uses -yaw)."""
    c = torch.cos(yaw)
    s = torch.sin(yaw)
    # [[c, -s],[s,c]]
    return torch.stack(
        [torch.stack([c, -s], dim=-1), torch.stack([s, c], dim=-1)],
        dim=-2,
    )


def smoothstep(x: torch.Tensor) -> torch.Tensor:
    """Hermite smoothstep: 0→1 with zero-derivative at both ends."""
    x = torch.clamp(x, 0.0, 1.0)
    return x * x * (3.0 - 2.0 * x)


def _wrap_angle_np(theta: np.ndarray) -> np.ndarray:
    return np.arctan2(np.sin(theta), np.cos(theta))


def _resample_pose_sequence_np(
    xy: np.ndarray,
    yaw: np.ndarray,
    *,
    num_samples: int,
) -> tuple[np.ndarray, np.ndarray]:
    if xy.shape[0] == 1:
        return np.repeat(xy, num_samples, axis=0), np.repeat(yaw, num_samples, axis=0)

    diffs = np.diff(xy, axis=0)
    seg_lens = np.linalg.norm(diffs, axis=1)
    s = np.concatenate([np.zeros((1,), dtype=np.float64), np.cumsum(seg_lens, dtype=np.float64)], axis=0)
    if float(s[-1]) < 1e-9:
        return np.repeat(xy[:1], num_samples, axis=0), np.repeat(yaw[:1], num_samples, axis=0)

    s_new = np.linspace(0.0, float(s[-1]), num_samples, dtype=np.float64)
    x_new = np.interp(s_new, s, xy[:, 0])
    y_new = np.interp(s_new, s, xy[:, 1])
    yaw_unwrapped = np.unwrap(yaw)
    yaw_new = np.interp(s_new, s, yaw_unwrapped)
    return np.stack([x_new, y_new], axis=1), _wrap_angle_np(yaw_new)


def _sample_root_path_first_np(
    *,
    root_start_xy: np.ndarray,
    root_start_yaw: float,
    pallet_xy: np.ndarray,
    pallet_yaw: float,
    root_goal_xy: np.ndarray,
    traj_pre_dist_m: float,
    curve_min_span_m: float,
    final_straight_min_m: float,
    num_samples: int,
) -> tuple[np.ndarray, np.ndarray]:
    u_in = np.array([math.cos(pallet_yaw), math.sin(pallet_yaw)], dtype=np.float64)
    v_lat = np.array([-math.sin(pallet_yaw), math.cos(pallet_yaw)], dtype=np.float64)
    rel_root_start = root_start_xy - pallet_xy
    rel_root_goal = root_goal_xy - pallet_xy
    root_start_s = float(np.dot(rel_root_start, u_in))
    root_start_y = float(np.dot(rel_root_start, v_lat))
    root_goal_s = float(np.dot(rel_root_goal, u_in))
    root_pre_nominal_s = root_goal_s - float(traj_pre_dist_m)
    root_pre_s = max(root_pre_nominal_s, root_start_s + float(curve_min_span_m))
    root_pre_s = min(root_pre_s, root_goal_s - float(final_straight_min_m))
    root_pre = pallet_xy + root_pre_s * u_in

    num_curve = int(num_samples * 0.7)
    num_line = num_samples - num_curve

    span_s = max(root_pre_s - root_start_s, 1e-6)
    yaw_rel0 = math.atan2(math.sin(root_start_yaw - pallet_yaw), math.cos(root_start_yaw - pallet_yaw))
    slope0 = math.tan(yaw_rel0)
    a = (slope0 * span_s + 2.0 * root_start_y) / (span_s ** 3)
    b = (-2.0 * slope0 * span_s - 3.0 * root_start_y) / (span_s ** 2)

    ds_curve = np.linspace(0.0, span_s, num_curve, dtype=np.float64).reshape(-1, 1)
    y_curve = a * ds_curve ** 3 + b * ds_curve ** 2 + slope0 * ds_curve + root_start_y
    dy_ds = 3.0 * a * ds_curve ** 2 + 2.0 * b * ds_curve + slope0
    s_curve = root_start_s + ds_curve
    root_pts_curve = pallet_xy + s_curve * u_in + y_curve * v_lat
    root_curve_dirs = u_in.reshape(1, 2) + dy_ds * v_lat.reshape(1, 2)
    root_curve_tangents = root_curve_dirs / np.maximum(np.linalg.norm(root_curve_dirs, axis=1, keepdims=True), 1e-9)
    root_curve_tangents[0] = np.array([math.cos(root_start_yaw), math.sin(root_start_yaw)], dtype=np.float64)
    root_curve_tangents[-1] = u_in

    if num_line > 0:
        t_line = np.linspace(0.0, 1.0, num_line + 1, dtype=np.float64).reshape(-1, 1)[1:]
        root_pts_line = (1.0 - t_line) * root_pre + t_line * root_goal_xy
        root_line_tangents = np.repeat(u_in.reshape(1, 2), num_line, axis=0)
        root_pts = np.concatenate([root_pts_curve, root_pts_line], axis=0)
        root_tangents = np.concatenate([root_curve_tangents, root_line_tangents], axis=0)
    else:
        root_pts = root_pts_curve
        root_tangents = root_curve_tangents
    return root_pts, root_tangents


def _sample_rs_root_path_np(
    *,
    root_start_xy: np.ndarray,
    root_start_yaw: float,
    root_goal_xy: np.ndarray,
    root_goal_yaw: float,
    min_turn_radius_m: float,
    sample_step_m: float,
    num_samples: int,
) -> tuple[np.ndarray, np.ndarray] | None:
    world_pts = exact_rs.rs_sample_path(
        float(root_start_xy[0]),
        float(root_start_xy[1]),
        float(root_start_yaw),
        float(root_goal_xy[0]),
        float(root_goal_xy[1]),
        float(root_goal_yaw),
        float(min_turn_radius_m),
        step=float(sample_step_m),
    )
    if not world_pts:
        return None
    xy = np.asarray([[pt[0], pt[1]] for pt in world_pts], dtype=np.float64)
    yaw = np.asarray([pt[2] for pt in world_pts], dtype=np.float64)
    root_pts, root_yaw = _resample_pose_sequence_np(xy, yaw, num_samples=num_samples)
    root_tangents = np.stack([np.cos(root_yaw), np.sin(root_yaw)], axis=1)
    return root_pts, root_tangents


def _rs_local_goal(start_xy: np.ndarray, start_yaw: float, goal_xy: np.ndarray, goal_yaw: float) -> tuple[float, float, float]:
    dx = float(goal_xy[0] - start_xy[0])
    dy = float(goal_xy[1] - start_xy[1])
    cos_t = math.cos(float(start_yaw))
    sin_t = math.sin(float(start_yaw))
    lx = dx * cos_t + dy * sin_t
    ly = -dx * sin_t + dy * cos_t
    lphi = math.atan2(math.sin(float(goal_yaw - start_yaw)), math.cos(float(goal_yaw - start_yaw)))
    return -lx, -ly, lphi


def _rs_candidate_stats(segs: list[tuple[str, float]]) -> dict[str, float | int | bool]:
    total = float(sum(abs(seg_len) for _, seg_len in segs))
    reverse = float(sum(abs(seg_len) for _, seg_len in segs if seg_len < 0.0))
    switches = sum(
        (segs[i][1] >= 0.0) != (segs[i - 1][1] >= 0.0)
        for i in range(1, len(segs))
    )
    final_forward = bool(segs and segs[-1][1] > 0.0)
    return {
        "total_length_m": total,
        "reverse_length_m": reverse,
        "reverse_frac": reverse / max(total, 1e-9),
        "direction_switches": int(switches),
        "final_forward": final_forward,
    }


def _choose_forward_preferred_rs_path(
    *,
    root_start_xy: np.ndarray,
    root_start_yaw: float,
    root_goal_xy: np.ndarray,
    root_goal_yaw: float,
    min_turn_radius_m: float,
    sample_step_m: float,
    num_samples: int,
    max_candidates: int,
    max_extra_length_m: float,
    max_reverse_frac: float,
    max_direction_switches: int,
    require_final_forward: bool,
    reverse_weight: float,
    switch_weight: float,
    terminal_reverse_penalty: float,
) -> tuple[np.ndarray, np.ndarray] | None:
    x_rs_goal, y_rs_goal, th_rs_goal = _rs_local_goal(root_start_xy, root_start_yaw, root_goal_xy, root_goal_yaw)
    all_segs = exact_rs.rs_all_paths(x_rs_goal, y_rs_goal, th_rs_goal, float(min_turn_radius_m))
    if not all_segs:
        return None

    shortest_total = float(sum(abs(seg_len) for _, seg_len in all_segs[0]))
    sampled_paths = exact_rs.rs_sample_path_multi(
        float(root_start_xy[0]),
        float(root_start_xy[1]),
        float(root_start_yaw),
        float(root_goal_xy[0]),
        float(root_goal_xy[1]),
        float(root_goal_yaw),
        float(min_turn_radius_m),
        step=float(sample_step_m),
        max_paths=min(int(max_candidates), len(all_segs)),
    )
    candidates: list[tuple[float, np.ndarray, np.ndarray]] = []
    for rank, (segs, world_pts) in enumerate(zip(all_segs[: len(sampled_paths)], sampled_paths), start=1):
        stats = _rs_candidate_stats(segs)
        if float(stats["total_length_m"]) > shortest_total + float(max_extra_length_m):
            continue
        if float(stats["reverse_frac"]) > float(max_reverse_frac):
            continue
        if int(stats["direction_switches"]) > int(max_direction_switches):
            continue
        if bool(require_final_forward) and not bool(stats["final_forward"]):
            continue

        score = (
            float(stats["total_length_m"])
            + float(reverse_weight) * float(stats["reverse_length_m"])
            + float(switch_weight) * int(stats["direction_switches"])
            + (0.0 if bool(stats["final_forward"]) else float(terminal_reverse_penalty))
        )
        xy = np.asarray([[pt[0], pt[1]] for pt in world_pts], dtype=np.float64)
        yaw = np.asarray([pt[2] for pt in world_pts], dtype=np.float64)
        root_pts, root_yaw = _resample_pose_sequence_np(xy, yaw, num_samples=num_samples)
        root_tangents = np.stack([np.cos(root_yaw), np.sin(root_yaw)], axis=1)
        candidates.append((score, root_pts, root_tangents))

    if not candidates:
        return None
    best = min(candidates, key=lambda item: item[0])
    return best[1], best[2]


def _spawn_ground_plane_with_fallback(prim_path: str, cfg) -> None:
    """Spawn the default Isaac ground plane, but fall back to a local mesh floor on asset load glitches."""
    usd_path = str(getattr(cfg, "usd_path", "") or "")
    if not usd_path or not os.path.isfile(usd_path):
        print(
            "[warn] Ground plane USD is not a verified local file; using local mesh fallback directly: "
            f"usd_path={usd_path or '<empty>'}"
        )
        _spawn_local_ground_plane(prim_path=prim_path, cfg=cfg)
        return

    try:
        spawn_ground_plane(prim_path=prim_path, cfg=cfg)
        return
    except Exception as exc:
        error_text = str(exc)
        recoverable = "Stage.GetPrimAtPath(Stage, NoneType)" in error_text
        if not recoverable:
            raise
        print(
            "[warn] spawn_ground_plane failed while resolving the default grid plane "
            f"('{error_text}'); falling back to a local mesh ground plane."
        )
    _spawn_local_ground_plane(prim_path=prim_path, cfg=cfg)


def _spawn_local_ground_plane(prim_path: str, cfg) -> None:
    """Create a simple box-mesh floor without depending on remote USD assets."""
    import trimesh
    from isaaclab.terrains.utils import create_prim_from_mesh

    size_x, size_y = cfg.size
    thickness = 0.02
    mesh = trimesh.creation.box(extents=(float(size_x), float(size_y), thickness))

    visual_material = None
    if getattr(cfg, "color", None) is not None:
        visual_material = sim_utils.PreviewSurfaceCfg(diffuse_color=cfg.color)

    create_prim_from_mesh(
        prim_path,
        mesh,
        translation=(0.0, 0.0, -0.5 * thickness),
        visual_material=visual_material,
        physics_material=getattr(cfg, "physics_material", None),
    )
    print(
        "[info] Local mesh ground plane created successfully: "
        f"path={prim_path}, size=({float(size_x):.1f}, {float(size_y):.1f}), thickness={thickness:.3f}"
    )


def _force_pallet_dynamic(stage, pallet_prim_path: str):
    """确保托盘是动态刚体（不是 kinematic）
    
    遍历托盘 prim 及其所有子 prim，将所有 RigidBodyAPI 设置为非 kinematic。
    """
    from pxr import Usd, UsdPhysics
    
    root_prim = stage.GetPrimAtPath(pallet_prim_path)
    if not root_prim.IsValid():
        print(f"[警告] 找不到托盘 prim: {pallet_prim_path}")
        return
    
    # 遍历托盘及其所有子 prim（使用 Usd.PrimRange 兼容所有 USD 版本）
    prims_to_process = list(Usd.PrimRange(root_prim))
    
    for prim in prims_to_process:
        if prim.HasAPI(UsdPhysics.RigidBodyAPI):
            rb_api = UsdPhysics.RigidBodyAPI(prim)
            # 确保是动态刚体
            rb_api.GetRigidBodyEnabledAttr().Set(True)
            rb_api.GetKinematicEnabledAttr().Set(False)
            print(f"[信息] 已设置 {prim.GetPath()} 为动态刚体")


def _force_pallet_convex_decomposition(stage, pallet_prim_path: str):
    """为托盘设置凸分解碰撞体，使 pocket 可以被插入
    
    遍历托盘 prim 及其所有子 prim，为所有带有碰撞体的 prim 设置凸分解。
    """
    from pxr import Usd, UsdPhysics, PhysxSchema, UsdGeom
    
    root_prim = stage.GetPrimAtPath(pallet_prim_path)
    if not root_prim.IsValid():
        print(f"[警告] 找不到托盘 prim: {pallet_prim_path}")
        return
    
    # 遍历托盘及其所有子 prim（使用 Usd.PrimRange 兼容所有 USD 版本）
    prims_to_process = list(Usd.PrimRange(root_prim))
    
    applied_count = 0
    for prim in prims_to_process:
        # 检查是否有 Mesh 几何体或已有碰撞 API
        has_mesh = prim.IsA(UsdGeom.Mesh)
        has_collision = prim.HasAPI(UsdPhysics.CollisionAPI)
        
        if has_mesh or has_collision:
            # 设置碰撞近似为凸分解
            mesh_collision_api = UsdPhysics.MeshCollisionAPI.Apply(prim)
            mesh_collision_api.GetApproximationAttr().Set("convexDecomposition")
            
            # 凸分解参数
            convex_api = PhysxSchema.PhysxConvexDecompositionCollisionAPI.Apply(prim)
            convex_api.GetMaxConvexHullsAttr().Set(8)   # 最大凸体数（从32降到8，平衡精度与性能）
            convex_api.GetHullVertexLimitAttr().Set(64)  # 每个凸体最大顶点数
            applied_count += 1
    
    print(f"[信息] 凸分解已应用到 {applied_count} 个 prim")


class ForkliftPalletInsertLiftEnv(DirectRLEnv):
    cfg: ForkliftPalletInsertLiftEnvCfg

    def __init__(self, cfg: ForkliftPalletInsertLiftEnvCfg, render_mode: str | None = None, **kwargs):
        # _setup_scene() 会在 super().__init__() 内被调用，因此相机状态必须先初始化。
        self._camera_enabled = bool(getattr(cfg, "use_camera", False))
        self._asym_enabled = bool(getattr(cfg, "use_asymmetric_critic", False))
        self._stage_1_mode = bool(getattr(cfg, "stage_1_mode", False))
        # Phase 1A v2: 21D 几何边缘观测开关（与 image / 15D 三选一，互斥）
        self._geo_edge_enabled = bool(getattr(cfg, "enable_geo_edge_obs", False))
        if self._geo_edge_enabled:
            # 几何观测路径：单一 21D flat tensor，不走 image，不开 asymmetric critic
            cfg.observation_space = 21
            self._camera_enabled = False
            self._asym_enabled = False
        elif self._camera_enabled:
            cfg.observation_space = {
                "image": [3, int(cfg.camera_height), int(cfg.camera_width)],
                "proprio": int(cfg.easy8_dim),
            }
        else:
            cfg.observation_space = 15
        cfg.state_space = int(cfg.privileged_dim) if self._asym_enabled else 0
        self._camera_initialized = False
        self._camera = None
        self._warned_camera_fallback = False
        super().__init__(cfg, render_mode, **kwargs)

        self.robot: Articulation = self.scene.articulations["robot"]
        self.pallet: RigidObject = self.scene.rigid_objects["pallet"]

        # joint indices：将关节名字映射为索引，便于后续批量设置目标
        self._front_wheel_ids, _ = self.robot.find_joints(["left_front_wheel_joint", "right_front_wheel_joint"], preserve_order=True)
        self._back_wheel_ids, _ = self.robot.find_joints(["left_back_wheel_joint", "right_back_wheel_joint"], preserve_order=True)
        self._rotator_ids, _ = self.robot.find_joints(["left_rotator_joint", "right_rotator_joint"], preserve_order=True)
        # separate left/right rotator IDs for order-independent steering
        self._left_rotator_id, _ = self.robot.find_joints(["left_rotator_joint"], preserve_order=True)
        self._right_rotator_id, _ = self.robot.find_joints(["right_rotator_joint"], preserve_order=True)
        self._lift_id, _ = self.robot.find_joints(["lift_joint"], preserve_order=True)
        self._lift_id = self._lift_id[0]

        # ---- 基础缓存 ----
        # actions: 当前步动作缓存（归一化动作）
        # _last_insert_depth: 上一步插入深度（用于安全制动与奖励增量）
        # _fork_tip_z0: reset 时 fork tip 的基准高度
        # _hold_counter: 成功条件保持计数器
        # _lift_pos_target: lift 关节位置目标（位置控制）
        # 无论 action_space 是 2 还是 3，内部统一使用 3 维动作缓存
        self.actions = torch.zeros((self.num_envs, 3), device=self.device)
        self.previous_actions = torch.zeros((self.num_envs, 3), device=self.device)
        self._last_insert_depth = torch.zeros((self.num_envs,), device=self.device)
        self._fork_tip_z0 = torch.zeros((self.num_envs,), device=self.device)
        # S1.0O-C2: 使用 float 以支持衰减（原 S1.0N 为 int32）
        self._hold_counter = torch.zeros((self.num_envs,), dtype=torch.float32, device=self.device)
        self._last_hold_entry = torch.zeros((self.num_envs,), dtype=torch.bool, device=self.device)
        self._success_termination = torch.zeros((self.num_envs,), dtype=torch.bool, device=self.device)
        self._preinsert_push_termination = torch.zeros((self.num_envs,), dtype=torch.bool, device=self.device)
        self._lift_pos_target = torch.zeros((self.num_envs,), device=self.device)

        # ---- 实验 B: 论文原生 Reward 缓存 ----
        self._is_first_step = torch.ones((self.num_envs,), dtype=torch.bool, device=self.device)
        self._milestone_flags = torch.zeros((self.num_envs, 7), dtype=torch.bool, device=self.device)
        self._fly_counter = torch.zeros((self.num_envs,), dtype=torch.int32, device=self.device)
        self._stall_counter = torch.zeros((self.num_envs,), dtype=torch.int32, device=self.device)
        self._early_stop_fly = torch.zeros((self.num_envs,), dtype=torch.bool, device=self.device)
        self._early_stop_stall = torch.zeros((self.num_envs,), dtype=torch.bool, device=self.device)
        
        # S1.0Q Batch-3: dead-zone stuck detector
        self._dz_stuck_counter = torch.zeros((self.num_envs,), dtype=torch.int32, device=self.device)
        self._prev_y_err = torch.zeros((self.num_envs,), device=self.device)
        self._prev_yaw_err_deg = torch.zeros((self.num_envs,), device=self.device)
        self._early_stop_dz_stuck = torch.zeros((self.num_envs,), dtype=torch.bool, device=self.device)
        self._dz_stuck_fired = torch.zeros((self.num_envs,), dtype=torch.bool, device=self.device)
        
        # 实验 B: 轨迹缓存
        self._traj_pts = torch.zeros((self.num_envs, self.cfg.traj_num_samples, 2), device=self.device)
        self._traj_tangents = torch.zeros((self.num_envs, self.cfg.traj_num_samples, 2), device=self.device)
        self._traj_s_norm = torch.zeros((self.num_envs, self.cfg.traj_num_samples), device=self.device)
        self._prev_phi_traj = torch.zeros((self.num_envs,), device=self.device)
        # _reset_idx 中引用的遗留缓存（必须初始化以防 AttributeError）
        self._prev_phi_align = torch.zeros((self.num_envs,), device=self.device)
        self._prev_phi_lift_progress = torch.zeros((self.num_envs,), device=self.device)
        self._last_phi_total = torch.zeros((self.num_envs,), device=self.device)
        self._last_lift_pos = torch.zeros((self.num_envs,), device=self.device)
        self._prev_lift_height = torch.zeros((self.num_envs,), device=self.device)
        # S1.0Q: 死区撤退 shaping 状态量
        self._prev_insert_norm = torch.zeros((self.num_envs,), device=self.device)
        self._prev_in_dead_zone = torch.zeros((self.num_envs,), dtype=torch.bool, device=self.device)
        
        # 实验 3.2: 近场 commit 状态量
        self._prev_dist_front = torch.zeros((self.num_envs,), device=self.device)
        # S1.0Q-A2v2: 撤退窗口缓冲（环形缓冲区）
        self._insert_norm_window = torch.zeros(
            (self.num_envs, self.cfg.retreat_window_size), device=self.device)
        self._window_ptr = torch.zeros((self.num_envs,), dtype=torch.long, device=self.device)
        self._window_filled = torch.zeros((self.num_envs,), dtype=torch.bool, device=self.device)
        # S1.0Q: 横向精调 delta shaping 状态量
        self._prev_phi_lat = torch.zeros((self.num_envs,), device=self.device)
        # S1.0S Phase-2: 举升里程碑 flags (10cm, 20cm)
        self._milestone_lift_10cm = torch.zeros((self.num_envs,), dtype=torch.bool, device=self.device)
        self._milestone_lift_20cm = torch.zeros((self.num_envs,), dtype=torch.bool, device=self.device)
        # S1.0T: 高举升里程碑 flags (50cm, 75cm)
        self._milestone_lift_50cm = torch.zeros((self.num_envs,), dtype=torch.bool, device=self.device)
        self._milestone_lift_75cm = torch.zeros((self.num_envs,), dtype=torch.bool, device=self.device)
        # S1.0S Phase-R: 远场大横偏修正 delta shaping 状态量
        self._prev_y_err_far = torch.zeros((self.num_envs,), device=self.device)
        # S1.0S Phase-3: 全局进展停滞检测器
        self._global_stall_counter = torch.zeros((self.num_envs,), dtype=torch.int32, device=self.device)
        self._prev_phi_total_stall = torch.zeros((self.num_envs,), device=self.device)

        # ---- 实验 3.1: 参考轨迹走廊 (Trajectory-lite) ----
        self._traj_pts = torch.zeros((self.num_envs, self.cfg.traj_num_samples, 2), device=self.device)
        self._traj_tangents = torch.zeros((self.num_envs, self.cfg.traj_num_samples, 2), device=self.device)
        self._traj_s_norm = torch.zeros((self.num_envs, self.cfg.traj_num_samples), device=self.device)
        self._prev_phi_traj = torch.zeros((self.num_envs,), device=self.device)
        # Exp8.3：几何常量仅记录一次（与 summary 中 geom/* 一致）
        self._geom_constants_logged = False
        # Exp8.3 runtime U0：仅用于 sanity run 的一次性诊断日志开关。
        self._runtime_u0_logged = False
        # Exp8.3 runtime U0.5/U1：target_center family 接线诊断日志开关。
        self._runtime_u1_logged = False

        # S1.0z: Episode 级别成功率统计
        self._ep_success_count = 0
        self._ep_total_count = 0
        
        # 实验 0：push-free 成功率统计
        self._ep_push_free_success_count = 0
        self._ep_push_free_insert_count = 0

        # ---- 派生常量 ----
        # S1.0h 修复：符号 + → -
        # _pallet_front_x 指向托盘 pocket 开口（近端面，-X 侧），不是远端面
        # 叉车从 -X 方向接近，insert_depth = tip_x - _pallet_front_x > 0 表示已插入
        self._pallet_front_x = self.cfg.pallet_cfg.init_state.pos[0] - self.cfg.pallet_depth_m * 0.5
        self._insert_thresh = self.cfg.insert_fraction * self.cfg.pallet_depth_m
        # 成功判定需要的 hold 步数
        ctrl_dt = self.cfg.sim.dt * self.cfg.decimation
        self._hold_steps = max(1, int(self.cfg.hold_time_s / ctrl_dt))
        self._hold_logic_cfg = HoldLogicConfig(
            insert_thresh=self._insert_thresh,
            max_lateral_err_m=self.cfg.max_lateral_err_m,
            max_yaw_err_deg=self.cfg.max_yaw_err_deg,
            hysteresis_ratio=self.cfg.hysteresis_ratio,
            insert_exit_epsilon=self.cfg.insert_exit_epsilon,
            lift_delta_m=self.cfg.lift_delta_m,
            lift_exit_epsilon=self.cfg.lift_exit_epsilon,
            hold_counter_decay=self.cfg.hold_counter_decay,
            tip_align_entry_m=self.cfg.tip_align_entry_m,
            tip_align_exit_m=self.cfg.tip_align_exit_m,
            tip_align_near_dist=self.cfg.tip_align_near_dist,
            require_lift=not (self._stage_1_mode and self.cfg.stage1_success_without_lift),
        )

        # 便捷引用（从 PhysX view 手动刷新，因为 robot.data.joint_pos 在
        # Fabric clone 失败时不会被 scene.update() 刷新——所有值恒为 0）
        num_joints = len(self.robot.joint_names)
        self._joint_pos = torch.zeros((self.num_envs, num_joints), device=self.device)
        self._joint_vel = torch.zeros((self.num_envs, num_joints), device=self.device)

        # ---- fork tip 运动学偏移量（从 USD mesh 测量或回退到默认值） ----
        # body_pos_w 在 Fabric clone 失败或 body frame origin 重合时无法区分各 link，
        # 因此使用 root_pos + yaw-旋转的固定偏移 + lift_joint_pos 来估算 fork tip。
        self._fork_forward_offset, self._fork_z_base = self._measure_fork_offset_from_usd()

        # Phase 1A v2: 几何边缘观测预计算（相机内外参 + 端点局部坐标），
        # 必须在 self.device / self.num_envs 可用之后调用。
        if self._geo_edge_enabled:
            self._init_geometry_edge_obs()

        # 注：_fix_lift_joint_drive() 已移到 _setup_scene() 中 clone_environments() 之前调用，
        # 确保 PhysX 在 sim.reset() 时 bake 到正确的 DriveAPI 参数（stiffness=200000, 位置控制）。

    def _fix_lift_joint_drive(self):
        """覆盖 lift_joint 的 USD DriveAPI 参数为位置控制模式。

        forklift_c.usd 原始 DriveAPI 设置了 stiffness=100000, damping=10000。
        Isaac Lab 的 ImplicitActuatorCfg 会在 sim.reset() 时覆盖 PhysX drive 参数，
        但为确保 clone 前 USD stage 上的值也一致（双保险），这里直接修改。

        logs32 验证可行的参数组合：stiffness=200000, damping=10000, maxForce=50000。
        修改必须在 clone_environments() 之前（模板环境），clone 后自动继承。
        """
        from pxr import Usd, UsdPhysics

        try:
            stage = self.sim.stage
            robot_prim_path = self.cfg.robot_cfg.prim_path.replace("env_.*", "env_0")
            robot_prim = stage.GetPrimAtPath(robot_prim_path)
            if not robot_prim.IsValid():
                print("[lift_drive] 无法找到 robot prim，跳过")
                return

            for prim in Usd.PrimRange(robot_prim):
                if "lift" not in prim.GetName().lower():
                    continue

                # 检查 linear DriveAPI（prismatic joint）
                drive_api = UsdPhysics.DriveAPI.Get(prim, "linear")
                if not drive_api:
                    continue

                # 原始值
                old_stiff = drive_api.GetStiffnessAttr().Get() if drive_api.GetStiffnessAttr() else "N/A"
                old_damp = drive_api.GetDampingAttr().Get() if drive_api.GetDampingAttr() else "N/A"
                old_force = drive_api.GetMaxForceAttr().Get() if drive_api.GetMaxForceAttr() else "N/A"

                # 覆盖为位置控制模式（logs32 验证值）
                drive_api.GetStiffnessAttr().Set(200000.0)    # 位置控制刚度
                drive_api.GetDampingAttr().Set(10000.0)       # 阻尼
                drive_api.GetMaxForceAttr().Set(50000.0)      # 最大力 50kN

                # 新值
                new_stiff = drive_api.GetStiffnessAttr().Get()
                new_damp = drive_api.GetDampingAttr().Get()
                new_force = drive_api.GetMaxForceAttr().Get()

                print(f"[lift_drive] 已覆盖 {prim.GetPath()} DriveAPI(linear):")
                print(f"  stiffness: {old_stiff} → {new_stiff}")
                print(f"  damping:   {old_damp} → {new_damp}")
                print(f"  maxForce:  {old_force} → {new_force}")
                return

            print("[lift_drive] 未找到 lift joint DriveAPI")
        except Exception as e:
            print(f"[lift_drive] 修复 lift drive 失败: {e}")

    def _measure_fork_offset_from_usd(self) -> tuple[float, float]:
        """从 USD mesh 数据测量 fork tip 相对于 articulation root 的前向偏移和基准 z 高度。

        遍历 robot prim 下所有名称含 'lift'/'fork' 的 body 的 mesh 子节点，
        计算所有顶点的 bounding box，取最大 X 作为前向偏移（假设 USD 中 +X = 前进方向）。
        如果无法测量，则回退到保守默认值。

        Returns:
            (fork_forward_offset, fork_z_base):
                fork_forward_offset — 从 root origin 到 fork tip 的前向距离（m）
                fork_z_base — fork tip 在 root frame 中的基准 z 高度（m），不含 lift_joint 位移
        """
        from pxr import Usd, UsdGeom
        import numpy as np

        DEFAULT_FORWARD = 1.5   # 保守默认值（m），略小于典型叉车货叉长度
        DEFAULT_Z_BASE = 0.10   # 保守默认值（m）

        try:
            stage = self.sim.stage
            robot_prim_path = self.cfg.robot_cfg.prim_path.replace("env_.*", "env_0")
            robot_prim = stage.GetPrimAtPath(robot_prim_path)
            if not robot_prim.IsValid():
                print(f"[fork_offset] 无法找到 robot prim: {robot_prim_path}，使用默认偏移")
                return DEFAULT_FORWARD, DEFAULT_Z_BASE

            # ---- 获取 USD 单位缩放（很多 USD 用 cm 而非 m） ----
            meters_per_unit = 1.0
            if stage.HasAuthoredMetadata("metersPerUnit"):
                meters_per_unit = stage.GetMetadata("metersPerUnit")
            elif UsdGeom.GetStageMetersPerUnit(stage) != 0.0:
                meters_per_unit = UsdGeom.GetStageMetersPerUnit(stage)
            print(f"[fork_offset] USD metersPerUnit = {meters_per_unit}")

            # robot root 的 world transform（用于将顶点转到 robot local frame）
            robot_xformable = UsdGeom.Xformable(robot_prim)
            robot_xform = robot_xformable.ComputeLocalToWorldTransform(0.0)
            robot_inv = robot_xform.GetInverse()

            # 收集所有 mesh 顶点（在 robot local frame 中，单位为 m）
            all_points = []
            fork_points = []  # 仅 lift/fork 相关 mesh 的顶点

            for prim in Usd.PrimRange(robot_prim):
                if not prim.IsA(UsdGeom.Mesh):
                    continue
                mesh = UsdGeom.Mesh(prim)
                pts_attr = mesh.GetPointsAttr()
                if pts_attr is None:
                    continue
                pts = pts_attr.Get()
                if pts is None or len(pts) == 0:
                    continue

                # local-to-world transform 已包含层级中的所有 scale
                xformable = UsdGeom.Xformable(prim)
                xform = xformable.ComputeLocalToWorldTransform(0.0)

                # 转到 robot local frame 后再乘以 metersPerUnit 转为 m
                is_fork = any(
                    kw in str(prim.GetPath()).lower()
                    for kw in ("lift", "fork", "tine")
                )
                for pt in pts:
                    world_pt = xform.Transform(pt)
                    local_pt = robot_inv.Transform(world_pt)
                    pt_m = [local_pt[0] * meters_per_unit,
                            local_pt[1] * meters_per_unit,
                            local_pt[2] * meters_per_unit]
                    all_points.append(pt_m)
                    if is_fork:
                        fork_points.append(pt_m)

            if not all_points:
                print("[fork_offset] 未找到任何 mesh 顶点，使用默认偏移")
                return DEFAULT_FORWARD, DEFAULT_Z_BASE

            all_arr = np.array(all_points)
            all_min = all_arr.min(axis=0)
            all_max = all_arr.max(axis=0)
            extent = all_max - all_min

            # ---- 自动检测单位：如果最大维度 > 10m，假设 cm 单位 ----
            unit_scale = 1.0
            if max(extent) > 10.0:
                unit_scale = 0.01  # cm → m
                all_arr *= unit_scale
                all_min = all_arr.min(axis=0)
                all_max = all_arr.max(axis=0)
                extent = all_max - all_min
                print(f"[fork_offset] 检测到 cm 单位（extent>{10.0}），自动转换 ×{unit_scale}")
                if fork_points:
                    fork_points = [[p[0]*unit_scale, p[1]*unit_scale, p[2]*unit_scale]
                                   for p in fork_points]

            print(f"[fork_offset] 模型范围(m): X[{all_min[0]:.4f}, {all_max[0]:.4f}], "
                  f"Y[{all_min[1]:.4f}, {all_max[1]:.4f}], Z[{all_min[2]:.4f}, {all_max[2]:.4f}]")

            if fork_points:
                fork_arr = np.array(fork_points)
                fork_forward = float(fork_arr[:, 0].max())
                fork_z = float(fork_arr[:, 2].min())
                print(f"[fork_offset] lift/fork mesh: forward={fork_forward:.4f}m, z_base={fork_z:.4f}m")
                if 0.3 < fork_forward < 5.0:
                    return fork_forward, max(fork_z, 0.0)
                else:
                    print(f"[fork_offset] 测量值不合理 ({fork_forward:.4f}m)，尝试整体前向")
            else:
                print("[fork_offset] 未找到 lift/fork mesh，尝试整体前向")

            # 回退：使用整体最大前向 X
            overall_forward = float(all_max[0])
            overall_z_min = float(all_min[2])
            print(f"[fork_offset] 整体 forward_max={overall_forward:.4f}m, z_min={overall_z_min:.4f}m")
            if 0.3 < overall_forward < 5.0:
                return overall_forward, max(overall_z_min, 0.0)

            print(f"[fork_offset] 整体值也不合理，使用默认值")
            return DEFAULT_FORWARD, DEFAULT_Z_BASE

        except Exception as e:
            print(f"[fork_offset] USD mesh 测量失败: {e}，使用默认偏移")
            return DEFAULT_FORWARD, DEFAULT_Z_BASE

    def _setup_pallet_physics(self):
        """在环境克隆前，强制设置托盘物理属性

        必须在 clone_environments() 之前调用，确保模板环境的设置能被克隆继承。

        S1.0h 修复：
        - 使用 Isaac Lab 官方 schemas.define_rigid_body_properties() 创建 RigidBodyAPI
          （之前手动 UsdPhysics.RigidBodyAPI.Apply() 在 Nucleus 引用层上不生效）
        - 若根 prim 失败，回退到子 prim 逐个尝试
        - 所有关键 print 加 flush=True，避免 nohup 缓冲导致日志丢失
        """
        from pxr import Usd, UsdPhysics, PhysxSchema, UsdGeom
        from isaaclab.sim import schemas as rl_schemas

        stage = self.sim.stage

        # 诊断：修改前的 USD 状态（只看 env_0）
        diag_pallet_path = self.cfg.pallet_cfg.prim_path.replace("env_.*", "env_0")
        self._log_pallet_usd(stage, diag_pallet_path, label="修改前")
        self._log_pallet_physx(label="修改前")

        # 只修改模板环境（env_0），让克隆继承
        pallet_path = self.cfg.pallet_cfg.prim_path.replace("env_.*", "env_0")
        root_prim = stage.GetPrimAtPath(pallet_path)
        if not root_prim.IsValid():
            print(f"[警告] 找不到托盘 prim: {pallet_path}", flush=True)
            return

        # ---- Step 1: 创建 RigidBodyAPI（多级回退策略） ----
        # Nucleus 的 pallet.usd 不含 RigidBodyAPI。Isaac Lab spawn 时调用的
        # modify_rigid_body_properties 只修改已有 API，不会创建新 API（返回 False）。
        # 使用 define_rigid_body_properties（先创建再修改）来解决。
        rigid_cfg = sim_utils.RigidBodyPropertiesCfg(
            rigid_body_enabled=True,
            kinematic_enabled=False,
            disable_gravity=False,
            max_depenetration_velocity=1.0,
        )

        # 方案 A：在根 prim 上调用 Isaac Lab 官方 define API
        try:
            rl_schemas.define_rigid_body_properties(pallet_path, rigid_cfg, stage)
            print(f"[信息] define_rigid_body_properties 已调用: {pallet_path}", flush=True)
        except Exception as e:
            print(f"[警告] define_rigid_body_properties 在根 prim 失败: {e}", flush=True)

        rb_ok = root_prim.HasAPI(UsdPhysics.RigidBodyAPI)
        print(f"[诊断] 根 prim HasAPI(RigidBodyAPI) = {rb_ok}", flush=True)

        # 方案 B：根 prim 失败，逐个尝试子 prim（Xform / Mesh）
        if not rb_ok:
            print("[信息] 根 prim 未成功，尝试子 prim...", flush=True)
            for child in Usd.PrimRange(root_prim):
                if child == root_prim:
                    continue
                child_path = str(child.GetPath())
                child_type = child.GetTypeName()
                try:
                    rl_schemas.define_rigid_body_properties(child_path, rigid_cfg, stage)
                    if child.HasAPI(UsdPhysics.RigidBodyAPI):
                        print(f"[信息] RigidBodyAPI 成功应用到子 prim: "
                              f"{child_path} (type={child_type})", flush=True)
                        rb_ok = True
                        break
                except Exception as e:
                    print(f"[诊断] 子 prim {child_path} 失败: {e}", flush=True)

        # 方案 C：全部失败，用低级 USD API 硬写并打印明确错误
        if not rb_ok:
            print("[警告] define API 均失败，尝试低级 USD API...", flush=True)
            UsdPhysics.RigidBodyAPI.Apply(root_prim)
            rb_api = UsdPhysics.RigidBodyAPI(root_prim)
            rb_api.GetRigidBodyEnabledAttr().Set(True)
            rb_api.GetKinematicEnabledAttr().Set(False)
            rb_ok = root_prim.HasAPI(UsdPhysics.RigidBodyAPI)
            if rb_ok:
                print(f"[信息] 低级 API 成功: {pallet_path}", flush=True)
            else:
                print(f"[错误] 所有方案均无法创建 RigidBodyAPI，训练将失败！", flush=True)

        # 注意：不在根 Xform prim 上添加 CollisionAPI。
        # 碰撞形状只需在子 Mesh prim 上，根 Xform 加碰撞会导致双重碰撞检测，
        # 严重拖慢仿真速度（947 vs 17000 steps/s）。

        # ---- Step 2: 遍历子 prim 设置凸分解碰撞体（跳过根 prim） ----
        prims_to_process = list(Usd.PrimRange(root_prim))
        for prim in prims_to_process:
            # 跳过根 prim，只处理子 prim
            if prim == root_prim:
                continue

            # 已有 RigidBodyAPI 的子 prim 也强制设为动态
            if prim.HasAPI(UsdPhysics.RigidBodyAPI):
                rb = UsdPhysics.RigidBodyAPI(prim)
                rb.GetRigidBodyEnabledAttr().Set(True)
                rb.GetKinematicEnabledAttr().Set(False)

            # 为 Mesh / 已有碰撞的 prim 设置凸分解
            has_mesh = prim.IsA(UsdGeom.Mesh)
            has_collision = prim.HasAPI(UsdPhysics.CollisionAPI)

            if has_mesh or has_collision:
                # 确保有 CollisionAPI
                if not prim.HasAPI(UsdPhysics.CollisionAPI):
                    UsdPhysics.CollisionAPI.Apply(prim)
                mesh_collision_api = UsdPhysics.MeshCollisionAPI.Apply(prim)
                mesh_collision_api.GetApproximationAttr().Set("convexDecomposition")

                convex_api = PhysxSchema.PhysxConvexDecompositionCollisionAPI.Apply(prim)
                convex_api.GetMaxConvexHullsAttr().Set(8)  # 从32降到8，平衡精度与性能
                convex_api.GetHullVertexLimitAttr().Set(64)

        print("[信息] 托盘物理属性已设置完成（模板环境）", flush=True)
        # 诊断：修改后的 USD 状态（只看 env_0）
        self._log_pallet_usd(stage, diag_pallet_path, label="修改后")
        self._log_pallet_physx(label="修改后")

    def _log_pallet_usd(self, stage, pallet_path: str, label: str):
        """打印托盘 USD 物理属性诊断信息（仅用于排查问题）。"""
        from pxr import Usd, UsdPhysics, UsdGeom

        root_prim = stage.GetPrimAtPath(pallet_path)
        if not root_prim.IsValid():
            print(f"[诊断] {label} 找不到托盘 prim: {pallet_path}")
            return

        prims_to_process = list(Usd.PrimRange(root_prim))

        print("\n" + "=" * 60)
        print(f"[诊断] {label} 托盘 USD 状态: {pallet_path}")
        print(f"[诊断] prim 数量: {len(prims_to_process)}")

        rigid_body_count = 0
        collision_count = 0

        for prim in prims_to_process:
            prim_path = prim.GetPath()
            prim_type = prim.GetTypeName()

            if prim.HasAPI(UsdPhysics.RigidBodyAPI):
                rb_api = UsdPhysics.RigidBodyAPI(prim)
                rb_enabled = rb_api.GetRigidBodyEnabledAttr().Get()
                kinematic = rb_api.GetKinematicEnabledAttr().Get()
                print(
                    f"[诊断] RigidBody: {prim_path} type={prim_type} "
                    f"enabled={rb_enabled} kinematic={kinematic}"
                )
                rigid_body_count += 1

            has_collision = prim.HasAPI(UsdPhysics.CollisionAPI)
            has_mesh = prim.IsA(UsdGeom.Mesh)
            if has_collision or has_mesh:
                approx = None
                if prim.HasAPI(UsdPhysics.MeshCollisionAPI):
                    mesh_api = UsdPhysics.MeshCollisionAPI(prim)
                    approx = mesh_api.GetApproximationAttr().Get()
                print(
                    f"[诊断] Collision: {prim_path} type={prim_type} "
                    f"collision_api={has_collision} mesh={has_mesh} approx={approx}"
                )
                collision_count += 1

        if rigid_body_count == 0:
            print("[诊断] 未发现 RigidBodyAPI，托盘可能没有刚体属性")

        print(f"[诊断] RigidBody 数量: {rigid_body_count}")
        print(f"[诊断] Collision/Mesh 数量: {collision_count}")
        print("=" * 60 + "\n")

    def _log_pallet_physx(self, label: str):
        """打印 PhysX 运行时视图的基本信息（可用性诊断）。"""
        if not hasattr(self, "pallet"):
            return
        if not hasattr(self.pallet, "root_physx_view"):
            print(f"[诊断] {label} PhysX view 不可用（root_physx_view 缺失）")
            return

        view = self.pallet.root_physx_view
        count = getattr(view, "count", None)
        print(f"[诊断] {label} PhysX view 已初始化, count={count}")
        if hasattr(view, "get_kinematic_enabled"):
            try:
                kin = view.get_kinematic_enabled()
                print(f"[诊断] {label} PhysX kinematic: {kin}")
            except Exception as exc:
                print(f"[诊断] {label} PhysX kinematic 读取失败: {exc}")
        else:
            print(f"[诊断] {label} PhysX 无直接 kinematic 读取接口")

    # ---------------------------
    # Scene setup
    # ---------------------------
    def _setup_scene(self):
        """构建场景与资产。

        注意顺序：
        1) 创建资产（robot/pallet）
        2) 修改模板环境（env_0）的物理属性
        3) 在克隆前修复 lift joint DriveAPI
        4) 克隆环境并加入场景
        """
        # assets
        self.robot = Articulation(self.cfg.robot_cfg)
        self.pallet = RigidObject(self.cfg.pallet_cfg)

        # strict body-follow camera: body 不存在则直接失败（不做 fallback）
        if self._camera_enabled:
            mount_body = str(getattr(self.cfg, "camera_mount_body", "body"))
            mount_prim = f"/World/envs/env_0/Robot/{mount_body}"
            stage = self.sim.stage
            if not stage.GetPrimAtPath(mount_prim).IsValid():
                robot_prim = stage.GetPrimAtPath("/World/envs/env_0/Robot")
                candidates = [child.GetName() for child in robot_prim.GetChildren()] if robot_prim.IsValid() else []
                raise RuntimeError(
                    f"[camera] mount body prim not found: {mount_prim}. available={candidates}"
                )

            # @configclass 中嵌套的 tiled_camera 不会随着 camera_* 字段自动同步，必须运行时显式覆盖。
            self.cfg.tiled_camera.prim_path = f"/World/envs/env_.*/Robot/{mount_body}/Camera"
            self.cfg.tiled_camera.offset.pos = self.cfg.camera_pos_local
            self.cfg.tiled_camera.width = int(self.cfg.camera_width)
            self.cfg.tiled_camera.height = int(self.cfg.camera_height)

            hfov_rad = math.radians(float(self.cfg.camera_hfov_deg))
            horizontal_aperture = float(self.cfg.tiled_camera.spawn.horizontal_aperture)
            focal_length = horizontal_aperture / (2.0 * math.tan(hfov_rad / 2.0))
            self.cfg.tiled_camera.spawn.focal_length = focal_length

            roll_deg, pitch_deg, yaw_deg = self.cfg.camera_rpy_local_deg
            cr = math.cos(math.radians(roll_deg) * 0.5)
            sr = math.sin(math.radians(roll_deg) * 0.5)
            cp = math.cos(math.radians(pitch_deg) * 0.5)
            sp = math.sin(math.radians(pitch_deg) * 0.5)
            cy = math.cos(math.radians(yaw_deg) * 0.5)
            sy = math.sin(math.radians(yaw_deg) * 0.5)
            w = cr * cp * cy + sr * sp * sy
            x = sr * cp * cy - cr * sp * sy
            y = cr * sp * cy + sr * cp * sy
            z = cr * cp * sy - sr * sp * cy
            self.cfg.tiled_camera.offset.rot = (w, x, y, z)

            self._camera = TiledCamera(self.cfg.tiled_camera)
            self._camera_initialized = True

        # 在克隆之前修改模板环境（env_0）的托盘物理属性
        self._setup_pallet_physics()

        # 在克隆之前修复 lift_joint DriveAPI（USD 原始 stiffness=100000 会锁死关节）
        # 必须在 clone_environments() 之前，这样修改会继承到所有克隆环境；
        # 也必须在 sim.reset() 之前，这样 PhysX bake 时读到的就是 stiffness=0。
        self._fix_lift_joint_drive()

        # ground
        _spawn_ground_plane_with_fallback(prim_path="/World/ground", cfg=self.cfg.ground_cfg)

        # clone envs
        self.scene.clone_environments(copy_from_source=False)

        # collision filtering (needed for CPU sim)
        # Note: `self.device` may be either a string ("cpu") or torch.device("cpu").
        if getattr(self.device, "type", str(self.device)) == "cpu":
            self.scene.filter_collisions(global_prim_paths=[])

        # add to scene
        self.scene.articulations["robot"] = self.robot
        self.scene.rigid_objects["pallet"] = self.pallet
        if self._camera_enabled and self._camera is not None:
            self.scene.sensors["tiled_camera"] = self._camera

        # 注意：托盘物理属性在 _setup_scene() 中 clone 之前设置

        # lights
        light_cfg = sim_utils.DomeLightCfg(intensity=2000.0, color=(0.75, 0.75, 0.75))
        light_cfg.func("/World/Light", light_cfg)

    # ---------------------------
    # Actions
    # ---------------------------
    def _pre_physics_step(self, actions: torch.Tensor) -> None:
        # store previous actions for ra penalty
        self.previous_actions[:] = self.actions[:]
        
        # store normalized actions
        clamped_actions = torch.clamp(actions, -1.0, 1.0)
        
        # 实验 1：如果 action_space 是 2 (approach-only)，自动补齐第 3 维 (lift) 为 0
        if clamped_actions.shape[1] == 2:
            lift_zeros = torch.zeros((clamped_actions.shape[0], 1), device=self.device)
            self.actions = torch.cat([clamped_actions, lift_zeros], dim=1)
        else:
            self.actions = clamped_actions

    def _apply_action(self) -> None:
        """将动作写入仿真。

        动作含义：
        - actions[:,0] 驱动（车轮角速度）
        - actions[:,1] 转向（前轮转角）
        - actions[:,2] 举升（lift 位置增量）
        """
        # decode actions
        drive = self.actions[:, 0] * self.cfg.wheel_speed_rad_s
        steer = self.actions[:, 1] * self.cfg.steer_angle_rad
        lift_v = self.actions[:, 2] * self.cfg.lift_speed_m_s

        if self._stage_1_mode:
            lift_v = torch.zeros_like(lift_v)

        # 只有上一拍已经进入 hold 几何时才冻结 drive/steer。
        # 这样“已经插进去但还没对正”的状态仍保留最后微调空间，不会被过早锁死。
        drive = torch.where(self._last_hold_entry, torch.zeros_like(drive), drive)
        steer = torch.where(self._last_hold_entry, torch.zeros_like(steer), steer)

        # set targets
        # wheels: velocity targets
        self.robot.set_joint_velocity_target(drive.unsqueeze(-1).repeat(1, len(self._front_wheel_ids)), joint_ids=self._front_wheel_ids)
        # back wheels follow (optional)
        self.robot.set_joint_velocity_target(drive.unsqueeze(-1).repeat(1, len(self._back_wheel_ids)), joint_ids=self._back_wheel_ids)

        # steering: position targets by joint name (order-independent)
        # left rotator needs SAME sign (verified by scripts/verify_joint_axes.py)
        # Previous assumption of mirrored axis was INCORRECT.
        steer_left = steer
        steer_right = steer
        self.robot.set_joint_position_target(steer_left.unsqueeze(-1), joint_ids=self._left_rotator_id)
        self.robot.set_joint_position_target(steer_right.unsqueeze(-1), joint_ids=self._right_rotator_id)

        # lift: position target (accumulated per substep)
        # logs32 验证：stiffness=200000 + set_joint_position_target 是唯一可行的 drive 控制方式
        # 注意：_apply_action() 每 env step 被调用 decimation 次，必须用 sim.dt 而非 step_dt
        self._lift_pos_target += lift_v * self.cfg.sim.dt
        self._lift_pos_target = torch.clamp(self._lift_pos_target, 0.0, 2.0)
        self.robot.set_joint_position_target(
            self._lift_pos_target.unsqueeze(-1), joint_ids=[self._lift_id]
        )

        # write to sim
        self.robot.write_data_to_sim()

    # ---------------------------
    # Observations / Rewards / Dones
    # ---------------------------
    def _compute_fork_tip(self) -> torch.Tensor:
        """运动学方法估算 fork tip 世界位置。

        使用 root_pos + yaw 旋转的固定前向偏移 + lift_joint 位移来计算。
        这比 body_pos_w 方法更可靠，因为 body_pos_w 在 Fabric clone 失败或
        body frame origin 重合时（如 forklift_c.usd）无法区分各 link。

        前向偏移量 (_fork_forward_offset) 在 __init__ 中从 USD mesh 数据测量，
        或回退到保守默认值。

        Returns:
            tip: (N, 3) tensor — fork tip 的世界坐标
        """
        root_pos = self.robot.data.root_pos_w   # (N, 3)
        yaw = _quat_to_yaw(self.robot.data.root_quat_w)  # (N,)
        lift_pos = self._joint_pos[:, self._lift_id]      # (N,) lift joint 位移

        cos_yaw = torch.cos(yaw)
        sin_yaw = torch.sin(yaw)

        tip_x = root_pos[:, 0] + self._fork_forward_offset * cos_yaw
        tip_y = root_pos[:, 1] + self._fork_forward_offset * sin_yaw
        tip_z = root_pos[:, 2] + self._fork_z_base + lift_pos

        return torch.stack([tip_x, tip_y, tip_z], dim=-1)

    def _compute_fork_center(self) -> torch.Tensor:
        """计算叉臂的几何中心世界位置。
        
        基于 fork tip 的位置，向后退回叉臂长度的一半。
        假设叉臂长度约为 1.2 米，因此向后退 0.6 米。
        """
        tip = self._compute_fork_tip()
        yaw = _quat_to_yaw(self.robot.data.root_quat_w)
        
        # 叉臂长度约 1.2m，中心在尖端后方 0.6m
        center_x = tip[:, 0] - 0.6 * torch.cos(yaw)
        center_y = tip[:, 1] - 0.6 * torch.sin(yaw)
        center_z = tip[:, 2]
        
        return torch.stack([center_x, center_y, center_z], dim=-1)

    def _compute_fork_center_from_root_lift(
        self,
        root_pos: torch.Tensor,
        root_quat: torch.Tensor,
        lift_pos: torch.Tensor,
    ) -> torch.Tensor:
        """由已写入仿真的 root + lift 关节位姿计算 fork_center（与 _compute_fork_center 同源）。

        Args:
            root_pos: (M, 3)
            root_quat: (M, 4) wxyz
            lift_pos: (M,) 与 _lift_id 对应的举升关节位置
        """
        yaw = _quat_to_yaw(root_quat)
        cos_yaw = torch.cos(yaw)
        sin_yaw = torch.sin(yaw)
        tip_x = root_pos[:, 0] + self._fork_forward_offset * cos_yaw
        tip_y = root_pos[:, 1] + self._fork_forward_offset * sin_yaw
        tip_z = root_pos[:, 2] + self._fork_z_base + lift_pos
        center_x = tip_x - 0.6 * cos_yaw
        center_y = tip_y - 0.6 * sin_yaw
        return torch.stack([center_x, center_y, tip_z], dim=-1)

    def _exp83_success_center_s(self) -> float:
        """success 判定对应的 fork_center 轴向标量位置。"""
        pallet_depth = float(self.cfg.pallet_depth_m)
        s_front = -0.5 * pallet_depth
        return s_front + (float(self.cfg.insert_fraction) * pallet_depth - 0.6)

    def _exp83_front_center_s(self) -> float:
        """legacy target_center 对应的 fork_center 轴向标量位置。"""
        pallet_depth = float(self.cfg.pallet_depth_m)
        return -0.5 * pallet_depth + 0.6

    def _exp83_target_center_family_s(self) -> float:
        """当前 target_center family 统一使用的轴向标量位置。"""
        mode = self.cfg.exp83_target_center_family_mode
        if mode == "front_center":
            return self._exp83_front_center_s()
        if mode == "success_center":
            return self._exp83_success_center_s()
        raise ValueError(f"Unsupported exp83_target_center_family_mode: {mode}")

    def _exp83_target_center_xy(
        self,
        pallet_pos_xy: torch.Tensor,
        pallet_yaw: torch.Tensor,
        s_target: float,
    ) -> torch.Tensor:
        """按给定轴向标量位置生成 fork_center 目标点。"""
        u_in = torch.stack([torch.cos(pallet_yaw), torch.sin(pallet_yaw)], dim=-1)
        return pallet_pos_xy + float(s_target) * u_in

    def _exp83_target_center_family_dist(
        self,
        fork_center_xy: torch.Tensor,
        pallet_pos_xy: torch.Tensor,
        pallet_yaw: torch.Tensor,
    ) -> tuple[torch.Tensor, torch.Tensor]:
        """返回当前 family target_center 及其与 fork_center 的距离。"""
        target_center_family = self._exp83_target_center_xy(
            pallet_pos_xy, pallet_yaw, self._exp83_target_center_family_s()
        )
        dist_center_family = torch.norm(fork_center_xy - target_center_family, dim=-1)
        return dist_center_family, target_center_family

    def _exp83_rg_mask(
        self,
        *,
        center_y_err: torch.Tensor,
        yaw_err_deg: torch.Tensor,
        insert_depth: torch.Tensor,
        tip_y_err: torch.Tensor,
        dist_front: torch.Tensor,
        valid_insert_z: torch.Tensor,
    ) -> torch.Tensor:
        """与 hold/success 同源的 arrival 几何掩码。"""
        align_entry = (
            (center_y_err <= self.cfg.max_lateral_err_m)
            & (yaw_err_deg <= self.cfg.max_yaw_err_deg)
        )
        insert_entry = insert_depth >= self._insert_thresh
        tip_gate_active = dist_front <= self.cfg.tip_align_near_dist
        tip_entry = (~tip_gate_active) | (tip_y_err <= self.cfg.tip_align_entry_m)
        return insert_entry & valid_insert_z & align_entry & tip_entry

    def _exp83_out_of_bounds_mask(self, dist_center_family: torch.Tensor) -> torch.Tensor:
        """当前 family 下的 out_of_bounds 掩码。"""
        return dist_center_family > self.cfg.paper_out_of_bounds_dist

    def _exp83_traj_goal_s(self) -> float:
        """当前参考轨迹终点的轴向标量位置。"""
        pallet_depth = float(self.cfg.pallet_depth_m)
        s_front = -0.5 * pallet_depth
        mode = self.cfg.exp83_traj_goal_mode
        if mode == "front":
            return s_front
        if mode == "success_center":
            return self._exp83_success_center_s()
        raise ValueError(f"Unsupported exp83_traj_goal_mode: {mode}")

    # ==========================================================================
    # 实验 3.1: 参考轨迹走廊 (Trajectory-lite)
    # ==========================================================================
    def _build_reference_trajectory(
        self,
        env_ids: torch.Tensor,
        *,
        fork_center_xy: torch.Tensor | None = None,
        robot_yaw: torch.Tensor | None = None,
        pallet_pos_xy: torch.Tensor | None = None,
        pallet_yaw: torch.Tensor | None = None,
    ):
        """在 reset 时为每个 env 生成并缓存参考轨迹。
        先在 vehicle/root pose 空间里生成参考路径，再映射出 fork_center 路径。
        支持两种模型：
        - root_path_first: cubic + final straight
        - rs_exact: exact Reeds-Shepp over root pose

        当提供 fork_center_xy / robot_yaw / pallet_pos_xy / pallet_yaw 时，
        直接使用 reset 刚写入的张量，避免依赖 `robot.data` / `pallet.data` 同步时机（Exp8.3 B0′）。
        张量形状均为 (M,·)，M = len(env_ids)。
        """
        if len(env_ids) == 0:
            return
        if not bool(getattr(self.cfg, "use_reference_trajectory", True)):
            self._traj_pts[env_ids] = 0.0
            self._traj_tangents[env_ids] = 0.0
            self._traj_s_norm[env_ids] = 0.0
            return

        # 1. 获取起点位姿
        if fork_center_xy is None:
            fork_center = self._compute_fork_center()
            p0 = fork_center[env_ids, :2]
            yaw0 = _quat_to_yaw(self.robot.data.root_quat_w[env_ids])
        else:
            p0 = fork_center_xy
            yaw0 = robot_yaw
        t0 = torch.stack([torch.cos(yaw0), torch.sin(yaw0)], dim=-1)
        root_to_fc = max(float(self._fork_forward_offset) - 0.6, 0.0)
        root_start = p0 - root_to_fc * t0

        # 2. 获取托盘位姿与目标点
        if pallet_pos_xy is None:
            pallet_pos = self.pallet.data.root_pos_w[env_ids, :2]
            pallet_yaw_v = _quat_to_yaw(self.pallet.data.root_quat_w[env_ids])
        else:
            pallet_pos = pallet_pos_xy
            pallet_yaw_v = pallet_yaw
        u_in = torch.stack([torch.cos(pallet_yaw_v), torch.sin(pallet_yaw_v)], dim=-1)

        s_goal = self._exp83_traj_goal_s()
        p_goal = pallet_pos + s_goal * u_in
        root_goal = p_goal - root_to_fc * u_in
        num_samples = self.cfg.traj_num_samples
        traj_model = str(getattr(self.cfg, "traj_model", "root_path_first"))

        root_start_np = root_start.detach().cpu().numpy()
        yaw0_np = yaw0.detach().cpu().numpy()
        pallet_pos_np = pallet_pos.detach().cpu().numpy()
        pallet_yaw_np = pallet_yaw_v.detach().cpu().numpy()
        root_goal_np = root_goal.detach().cpu().numpy()

        pts_out = torch.zeros((len(env_ids), num_samples, 2), device=self.device)
        tangents_out = torch.zeros((len(env_ids), num_samples, 2), device=self.device)
        s_norm_out = torch.zeros((len(env_ids), num_samples), device=self.device)
        fallback_count = 0

        for local_idx in range(len(env_ids)):
            root_pts_np: np.ndarray
            root_tangents_np: np.ndarray
            if traj_model == "rs_exact":
                rs_payload = _sample_rs_root_path_np(
                    root_start_xy=root_start_np[local_idx],
                    root_start_yaw=float(yaw0_np[local_idx]),
                    root_goal_xy=root_goal_np[local_idx],
                    root_goal_yaw=float(pallet_yaw_np[local_idx]),
                    min_turn_radius_m=float(self.cfg.traj_rs_min_turn_radius_m),
                    sample_step_m=float(self.cfg.traj_rs_sample_step_m),
                    num_samples=int(num_samples),
                )
                if rs_payload is None:
                    if not bool(getattr(self.cfg, "traj_rs_fail_fallback_to_root_path_first", True)):
                        raise RuntimeError(
                            f"RS reference trajectory failed for env={int(env_ids[local_idx])}"
                        )
                    fallback_count += 1
                    root_pts_np, root_tangents_np = _sample_root_path_first_np(
                        root_start_xy=root_start_np[local_idx],
                        root_start_yaw=float(yaw0_np[local_idx]),
                        pallet_xy=pallet_pos_np[local_idx],
                        pallet_yaw=float(pallet_yaw_np[local_idx]),
                        root_goal_xy=root_goal_np[local_idx],
                        traj_pre_dist_m=float(self.cfg.traj_pre_dist_m),
                        curve_min_span_m=float(self.cfg.traj_vehicle_curve_min_span_m),
                        final_straight_min_m=float(self.cfg.traj_vehicle_final_straight_min_m),
                        num_samples=int(num_samples),
                    )
                else:
                    root_pts_np, root_tangents_np = rs_payload
            elif traj_model == "rs_forward_preferred":
                rs_payload = _choose_forward_preferred_rs_path(
                    root_start_xy=root_start_np[local_idx],
                    root_start_yaw=float(yaw0_np[local_idx]),
                    root_goal_xy=root_goal_np[local_idx],
                    root_goal_yaw=float(pallet_yaw_np[local_idx]),
                    min_turn_radius_m=float(self.cfg.traj_rs_min_turn_radius_m),
                    sample_step_m=float(self.cfg.traj_rs_sample_step_m),
                    num_samples=int(num_samples),
                    max_candidates=int(self.cfg.traj_rs_forward_preferred_max_candidates),
                    max_extra_length_m=float(self.cfg.traj_rs_forward_preferred_max_extra_length_m),
                    max_reverse_frac=float(self.cfg.traj_rs_forward_preferred_max_reverse_frac),
                    max_direction_switches=int(self.cfg.traj_rs_forward_preferred_max_direction_switches),
                    require_final_forward=bool(self.cfg.traj_rs_forward_preferred_require_final_forward),
                    reverse_weight=float(self.cfg.traj_rs_forward_preferred_reverse_weight),
                    switch_weight=float(self.cfg.traj_rs_forward_preferred_switch_weight),
                    terminal_reverse_penalty=float(self.cfg.traj_rs_forward_preferred_terminal_reverse_penalty),
                )
                if rs_payload is None:
                    if not bool(getattr(self.cfg, "traj_rs_fail_fallback_to_root_path_first", True)):
                        raise RuntimeError(
                            f"Forward-preferred RS reference trajectory failed for env={int(env_ids[local_idx])}"
                        )
                    fallback_count += 1
                    root_pts_np, root_tangents_np = _sample_root_path_first_np(
                        root_start_xy=root_start_np[local_idx],
                        root_start_yaw=float(yaw0_np[local_idx]),
                        pallet_xy=pallet_pos_np[local_idx],
                        pallet_yaw=float(pallet_yaw_np[local_idx]),
                        root_goal_xy=root_goal_np[local_idx],
                        traj_pre_dist_m=float(self.cfg.traj_pre_dist_m),
                        curve_min_span_m=float(self.cfg.traj_vehicle_curve_min_span_m),
                        final_straight_min_m=float(self.cfg.traj_vehicle_final_straight_min_m),
                        num_samples=int(num_samples),
                    )
                else:
                    root_pts_np, root_tangents_np = rs_payload
            elif traj_model == "root_path_first":
                root_pts_np, root_tangents_np = _sample_root_path_first_np(
                    root_start_xy=root_start_np[local_idx],
                    root_start_yaw=float(yaw0_np[local_idx]),
                    pallet_xy=pallet_pos_np[local_idx],
                    pallet_yaw=float(pallet_yaw_np[local_idx]),
                    root_goal_xy=root_goal_np[local_idx],
                    traj_pre_dist_m=float(self.cfg.traj_pre_dist_m),
                    curve_min_span_m=float(self.cfg.traj_vehicle_curve_min_span_m),
                    final_straight_min_m=float(self.cfg.traj_vehicle_final_straight_min_m),
                    num_samples=int(num_samples),
                )
            else:
                raise ValueError(f"Unsupported traj_model: {traj_model}")

            pts_np = root_pts_np + root_to_fc * root_tangents_np
            diffs_np = root_pts_np[1:, :] - root_pts_np[:-1, :]
            dists_np = np.linalg.norm(diffs_np, axis=1)
            s_cum_np = np.concatenate(
                [np.zeros((1,), dtype=np.float64), np.cumsum(dists_np, dtype=np.float64)],
                axis=0,
            )
            s_total = float(s_cum_np[-1]) + 1e-6

            pts_out[local_idx] = torch.from_numpy(pts_np).to(device=self.device, dtype=torch.float32)
            tangents_out[local_idx] = torch.from_numpy(root_tangents_np).to(device=self.device, dtype=torch.float32)
            s_norm_out[local_idx] = torch.from_numpy(s_cum_np / s_total).to(device=self.device, dtype=torch.float32)

        self._traj_pts[env_ids] = pts_out
        self._traj_tangents[env_ids] = tangents_out
        self._traj_s_norm[env_ids] = s_norm_out

        if traj_model in {"rs_exact", "rs_forward_preferred"} and fallback_count > 0:
            print(
                f"[traj_{traj_model}] fallback_to_root_path_first="
                f"{fallback_count}/{len(env_ids)} envs"
            )

    def _run_runtime_u0_check(
        self,
        env_ids: torch.Tensor,
        *,
        fork_center_xy: torch.Tensor,
        robot_yaw: torch.Tensor,
        pallet_pos_xy: torch.Tensor,
        pallet_yaw: torch.Tensor,
    ) -> None:
        """Exp8.3 runtime U0：在真实 env reset 后立即检查轨迹接线一致性。"""
        if not bool(getattr(self.cfg, "use_reference_trajectory", True)):
            return
        if not bool(getattr(self.cfg, "exp83_runtime_u0_enable", False)):
            return
        if len(env_ids) == 0:
            return

        eps_pos = float(self.cfg.exp83_runtime_u0_eps_pos_m)
        eps_yaw_deg = float(self.cfg.exp83_runtime_u0_eps_yaw_deg)
        env_ids = env_ids.long()

        traj_pts = self._traj_pts[env_ids]  # (M, S, 2)
        traj_tangents = self._traj_tangents[env_ids]  # (M, S, 2)
        p0 = traj_pts[:, 0, :]

        u_in = torch.stack([torch.cos(pallet_yaw), torch.sin(pallet_yaw)], dim=-1)
        s_goal = self._exp83_traj_goal_s()
        p_goal = pallet_pos_xy + s_goal * u_in
        p_end = traj_pts[:, -1, :]

        d_start = torch.norm(p0 - fork_center_xy, dim=-1)
        d_end = torch.norm(p_end - p_goal, dim=-1)

        dists = torch.norm(traj_pts - fork_center_xy.unsqueeze(1), dim=-1)
        d_traj, min_indices = torch.min(dists, dim=1)
        env_arange = torch.arange(len(env_ids), device=self.device)
        closest_tangent = traj_tangents[env_arange, min_indices]
        traj_yaw = torch.atan2(closest_tangent[:, 1], closest_tangent[:, 0])
        yaw_err = torch.atan2(
            torch.sin(robot_yaw - traj_yaw),
            torch.cos(robot_yaw - traj_yaw),
        )
        yaw_err_deg = torch.abs(yaw_err) * (180.0 / math.pi)

        fail_mask = (d_start > eps_pos) | (d_end > eps_pos) | (d_traj > eps_pos) | (yaw_err_deg > eps_yaw_deg)
        fail_count = int(fail_mask.sum().item())
        total = int(len(env_ids))
        max_d_start = float(d_start.max().item())
        max_d_end = float(d_end.max().item())
        max_d_traj = float(d_traj.max().item())
        max_yaw_deg = float(yaw_err_deg.max().item())
        summary = (
            "[runtime_u0] "
            f"fail={fail_count}/{total}, "
            f"max_d_start={max_d_start:.6f}, "
            f"max_d_end={max_d_end:.6f}, "
            f"max_d_traj={max_d_traj:.6f}, "
            f"max_yaw_deg={max_yaw_deg:.4f}, "
            f"eps_pos={eps_pos:.6f}, "
            f"eps_yaw_deg={eps_yaw_deg:.4f}"
        )
        if (not self._runtime_u0_logged) or fail_count > 0:
            print(summary)
            self._runtime_u0_logged = True

        if fail_count > 0 and bool(getattr(self.cfg, "exp83_runtime_u0_fail_fast", True)):
            raise RuntimeError(f"Exp8.3 runtime U0 failed: {summary}")

    def _run_runtime_u1_target_center_family_check(
        self,
        env_ids: torch.Tensor,
        *,
        pallet_pos_xy: torch.Tensor,
        pallet_yaw: torch.Tensor,
    ) -> None:
        """Exp8.3 runtime U0.5/U1：检查 r_d / rg / out_of_bounds 的 family 接线。"""
        if not bool(getattr(self.cfg, "use_reference_trajectory", True)):
            return
        if not bool(getattr(self.cfg, "exp83_runtime_u1_enable", False)):
            return
        if len(env_ids) == 0:
            return

        eps_m = float(self.cfg.exp83_runtime_u1_eps_m)
        probe_margin = float(self.cfg.exp83_runtime_u1_probe_margin_m)
        env_ids = env_ids.long()

        u_in = torch.stack([torch.cos(pallet_yaw), torch.sin(pallet_yaw)], dim=-1)

        s_front_center = self._exp83_front_center_s()
        s_success = self._exp83_success_center_s()
        s_family = self._exp83_target_center_family_s()
        s_traj = self._exp83_traj_goal_s()
        if self.cfg.exp83_target_center_family_mode == "front_center":
            s_alt = s_success
        else:
            s_alt = s_front_center

        family_center = self._exp83_target_center_xy(pallet_pos_xy, pallet_yaw, s_family)
        alt_center = self._exp83_target_center_xy(pallet_pos_xy, pallet_yaw, s_alt)
        traj_goal_center = self._exp83_target_center_xy(pallet_pos_xy, pallet_yaw, s_traj)
        oob_center = family_center + (self.cfg.paper_out_of_bounds_dist + probe_margin) * u_in

        def _eval_probe(probe_center_xy: torch.Tensor) -> tuple[torch.Tensor, torch.Tensor, torch.Tensor, torch.Tensor]:
            dist_center_family, _ = self._exp83_target_center_family_dist(
                probe_center_xy, pallet_pos_xy, pallet_yaw
            )
            tip_xy = probe_center_xy + 0.6 * u_in
            v_lat = torch.stack([-u_in[:, 1], u_in[:, 0]], dim=-1)
            center_y_err = torch.abs(torch.sum((probe_center_xy - pallet_pos_xy) * v_lat, dim=-1))
            tip_y_err = torch.abs(torch.sum((tip_xy - pallet_pos_xy) * v_lat, dim=-1))
            yaw_err_deg = torch.zeros_like(dist_center_family)
            s_front = -0.5 * float(self.cfg.pallet_depth_m)
            s_tip = torch.sum((tip_xy - pallet_pos_xy) * u_in, dim=-1)
            insert_depth = torch.clamp(s_tip - s_front, min=0.0)
            dist_front = torch.clamp(s_front - s_tip, min=0.0)
            rg = self._exp83_rg_mask(
                center_y_err=center_y_err,
                yaw_err_deg=yaw_err_deg,
                insert_depth=insert_depth,
                tip_y_err=tip_y_err,
                dist_front=dist_front,
                valid_insert_z=torch.ones_like(dist_center_family, dtype=torch.bool),
            )
            out_of_bounds = self._exp83_out_of_bounds_mask(dist_center_family)
            r_d = torch.clip(1.0 / (dist_center_family + 1e-5), 0.0, self.cfg.paper_reward_max)
            return dist_center_family, rg, out_of_bounds, r_d

        family_dist, family_rg, family_oob, family_r_d = _eval_probe(family_center)
        alt_dist, alt_rg, alt_oob, _ = _eval_probe(alt_center)
        traj_dist, traj_rg, traj_oob, _ = _eval_probe(traj_goal_center)
        oob_dist, oob_rg, oob_oob, _ = _eval_probe(oob_center)

        expected_alt_dist = abs(s_alt - s_family)
        expected_traj_dist = abs(s_traj - s_family)
        expected_oob_dist = float(self.cfg.paper_out_of_bounds_dist) + probe_margin
        expected_alt_rg = True
        expected_traj_rg = s_traj >= self._exp83_success_center_s()

        fail_mask = (
            (family_dist > eps_m) |
            (~family_rg) |
            family_oob |
            (torch.abs(family_r_d - float(self.cfg.paper_reward_max)) > 1e-6) |
            (torch.abs(alt_dist - expected_alt_dist) > eps_m) |
            (alt_rg != expected_alt_rg) |
            alt_oob |
            (torch.abs(traj_dist - expected_traj_dist) > eps_m) |
            (traj_rg != expected_traj_rg) |
            traj_oob |
            (torch.abs(oob_dist - expected_oob_dist) > eps_m) |
            oob_rg |
            (~oob_oob)
        )

        fail_count = int(fail_mask.sum().item())
        total = int(len(env_ids))
        summary = (
            "[runtime_u1_target_family] "
            f"fail={fail_count}/{total}, "
            f"mode={self.cfg.exp83_target_center_family_mode}, "
            f"s_front_center={s_front_center:.6f}, "
            f"s_family={s_family:.6f}, "
            f"s_traj={s_traj:.6f}, "
            f"delta_alt={expected_alt_dist:.6f}, "
            f"delta_traj={expected_traj_dist:.6f}, "
            f"traj_goal_inside_rg={int(expected_traj_rg)}, "
            f"max_family_d={float(family_dist.max().item()):.6f}, "
            f"max_alt_d_err={float(torch.abs(alt_dist - expected_alt_dist).max().item()):.6f}, "
            f"max_traj_d_err={float(torch.abs(traj_dist - expected_traj_dist).max().item()):.6f}, "
            f"max_oob_d_err={float(torch.abs(oob_dist - expected_oob_dist).max().item()):.6f}, "
            f"eps_m={eps_m:.6f}"
        )
        if (not self._runtime_u1_logged) or fail_count > 0:
            print(summary)
            self._runtime_u1_logged = True

        if fail_count > 0 and bool(getattr(self.cfg, "exp83_runtime_u1_fail_fast", True)):
            raise RuntimeError(f"Exp8.3 runtime U1 target-center-family failed: {summary}")

    def _query_reference_trajectory(self) -> tuple[torch.Tensor, torch.Tensor, torch.Tensor]:
        """查询当前叉臂中心在参考轨迹上的状态。
        返回:
            d_traj: 到轨迹的最短距离 (N,)
            yaw_traj_err_deg: 叉臂朝向与最近点切线的偏航误差 (N,)
            s_traj_norm: 最近点在轨迹上的归一化进度 (N,)
        """
        if not bool(getattr(self.cfg, "use_reference_trajectory", True)):
            zeros = torch.zeros((self.num_envs,), device=self.device)
            return zeros, zeros, zeros

        fork_center = self._compute_fork_center()
        query_pos = fork_center[:, :2]  # (N, 2)
        robot_yaw = _quat_to_yaw(self.robot.data.root_quat_w)  # (N,)

        # 计算到所有轨迹点的距离 (N, num_samples)
        dists = torch.norm(self._traj_pts - query_pos.unsqueeze(1), dim=-1)
        
        # 找到最近点的索引
        min_dists, min_indices = torch.min(dists, dim=1)  # (N,), (N,)
        
        # 提取最近点信息
        env_arange = torch.arange(self.num_envs, device=self.device)
        closest_tangent = self._traj_tangents[env_arange, min_indices]  # (N, 2)
        s_traj_norm = self._traj_s_norm[env_arange, min_indices]  # (N,)
        
        # 计算偏航误差
        traj_yaw = torch.atan2(closest_tangent[:, 1], closest_tangent[:, 0])
        yaw_err = torch.atan2(
            torch.sin(robot_yaw - traj_yaw),
            torch.cos(robot_yaw - traj_yaw)
        )
        yaw_traj_err_deg = torch.abs(yaw_err) * (180.0 / math.pi)

        return min_dists, yaw_traj_err_deg, s_traj_norm

    def _compute_phi_align(self, env_ids: torch.Tensor | None = None) -> torch.Tensor:
        """计算对齐势函数 phi_align（与 _get_rewards 同源几何）。

        用于 delta hold-align shaping 的状态缓存初始化（_reset_idx）和
        每步 delta 计算（_get_rewards）。

        Args:
            env_ids: 如果提供，只计算这些 env 的值；否则计算全部。

        Returns:
            phi_align: (len(env_ids),) 或 (N,) — 对齐势函数值 [0, 1]
        """
        if env_ids is not None:
            root_pos = self.robot.data.root_pos_w[env_ids]
            robot_yaw = _quat_to_yaw(self.robot.data.root_quat_w[env_ids])
            pallet_pos = self.pallet.data.root_pos_w[env_ids]
            pallet_yaw = _quat_to_yaw(self.pallet.data.root_quat_w[env_ids])
        else:
            root_pos = self.robot.data.root_pos_w
            robot_yaw = _quat_to_yaw(self.robot.data.root_quat_w)
            pallet_pos = self.pallet.data.root_pos_w
            pallet_yaw = _quat_to_yaw(self.pallet.data.root_quat_w)

        cp = torch.cos(pallet_yaw)
        sp = torch.sin(pallet_yaw)
        v_lat = torch.stack([-sp, cp], dim=-1)

        rel_robot = root_pos[:, :2] - pallet_pos[:, :2]
        y_err = torch.abs(torch.sum(rel_robot * v_lat, dim=-1))

        yaw_err = torch.atan2(
            torch.sin(robot_yaw - pallet_yaw),
            torch.cos(robot_yaw - pallet_yaw),
        )
        yaw_err_deg = torch.abs(yaw_err) * (180.0 / math.pi)

        phi_align = (
            torch.exp(-(y_err / self.cfg.hold_align_sigma_y) ** 2)
            * torch.exp(-(yaw_err_deg / self.cfg.hold_align_sigma_yaw) ** 2)
        )
        return phi_align

    # ---- Step-1: camera/asymmetric scaffolding helpers ----
    def _get_camera_image(self) -> torch.Tensor:
        """返回真实相机图像张量，统一为 (N,3,H,W), float32, [0,1]。"""
        h = int(getattr(self.cfg, "camera_height", 64))
        w = int(getattr(self.cfg, "camera_width", 64))

        if not self._camera_initialized or self._camera is None:
            raise RuntimeError("[camera] camera requested but not initialized")

        rgb = self._camera.data.output["rgb"]
        # 支持两种常见布局: (N,H,W,3) 或 (N,3,H,W)
        if rgb.ndim != 4:
            raise RuntimeError(f"[camera] unexpected rgb ndim={rgb.ndim}, expect 4")
        if rgb.shape[-1] == 3:
            rgb = rgb.permute(0, 3, 1, 2)
        elif rgb.shape[1] == 3:
            pass
        else:
            raise RuntimeError(f"[camera] unexpected rgb shape={tuple(rgb.shape)}")

        rgb = rgb.float()
        if rgb.max() > 1.0:
            rgb = rgb / 255.0
        rgb = torch.clamp(rgb, 0.0, 1.0)

        if torch.isnan(rgb).any() or torch.isinf(rgb).any():
            raise RuntimeError("[camera] rgb contains NaN/Inf")

        # shape 保护
        if rgb.shape[2] != h or rgb.shape[3] != w:
            raise RuntimeError(
                f"[camera] rgb shape mismatch, got {tuple(rgb.shape)}, expect (*,3,{h},{w})"
            )
        return rgb

    # ==========================================================================
    #  Phase 1A v2: 21D 几何边缘观测
    # ==========================================================================
    def _init_geometry_edge_obs(self) -> None:
        """预计算虚拟相机内外参与 4 个 pallet-local 端点（顶面短边）。

        body frame: X forward, Y left, Z up（Isaac 约定）
        camera frame: OpenCV 约定 X right, Y down, Z forward
        无 roll/yaw、pitch 由 cfg.geo_camera_pitch_deg 给出（正值 = nose down）。
        """
        cfg = self.cfg

        W = float(cfg.geo_camera_width)
        H = float(cfg.geo_camera_height)
        hfov = math.radians(float(cfg.geo_camera_hfov_deg))
        fx = (W * 0.5) / math.tan(hfov * 0.5)
        fy = fx
        cx = W * 0.5
        cy = H * 0.5

        self._geo_W = W
        self._geo_H = H
        self._geo_fx = fx
        self._geo_fy = fy
        self._geo_cx = cx
        self._geo_cy = cy
        self._geo_fov_margin = float(cfg.geo_camera_fov_margin)

        # body→camera 旋转矩阵：先 axis-swap (camera_X = -body_Y, camera_Y = -body_Z,
        # camera_Z = body_X)，再绕 camera X 轴 pitch（nose-down）。
        # 推导：相机三个基向量在 body frame 中的方向：
        #   right_b  = (0, -1, 0)
        #   down_b   = (-sin a, 0, -cos a)
        #   forward_b= (cos a, 0, -sin a)
        # 其中 a = pitch_deg (rad)。R_body_cam 的行向量即上述三个基向量。
        pitch_rad = math.radians(float(cfg.geo_camera_pitch_deg))
        sa = math.sin(pitch_rad)
        ca = math.cos(pitch_rad)
        R_body_cam = torch.tensor(
            [
                [0.0, -1.0, 0.0],
                [-sa, 0.0, -ca],
                [ca, 0.0, -sa],
            ],
            device=self.device,
            dtype=torch.float32,
        )
        self._geo_R_body_cam = R_body_cam  # (3, 3)
        self._geo_cam_pos_body = torch.tensor(
            cfg.geo_camera_pos_local_m, device=self.device, dtype=torch.float32
        )  # (3,)

        # 4 个 pallet-local 端点（顶面短边）
        # edge[0] = -X 短边（远端，欧标 1.2m × 1.8x = 2.16m → half 1.08）
        # edge[1] = +X 短边
        hd = float(cfg.geo_edge_half_depth_m)
        hw = float(cfg.geo_edge_half_width_m)
        tz = float(cfg.geo_edge_top_z_m)
        self._geo_edge_pts_local = torch.tensor(
            [
                [-hd, -hw, tz],   # edge0 endpoint A
                [-hd, +hw, tz],   # edge0 endpoint B
                [+hd, -hw, tz],   # edge1 endpoint A
                [+hd, +hw, tz],   # edge1 endpoint B
            ],
            device=self.device,
            dtype=torch.float32,
        )  # (4, 3)

    def _get_pallet_edges_world(self) -> torch.Tensor:
        """4 个 pallet-local 端点 → world frame，返回 (N, 4, 3)。"""
        N = self.num_envs
        K = self._geo_edge_pts_local.shape[0]  # 4

        pallet_pos = self.pallet.data.root_pos_w           # (N, 3)
        pallet_quat = self.pallet.data.root_quat_w         # (N, 4) (w,x,y,z)

        q = pallet_quat.unsqueeze(1).expand(N, K, 4).reshape(-1, 4)
        pts = self._geo_edge_pts_local.unsqueeze(0).expand(N, K, 3).reshape(-1, 3)
        pts_w_flat = quat_apply(q, pts)                    # (N*K, 3)
        pts_w = pts_w_flat.reshape(N, K, 3) + pallet_pos.unsqueeze(1)
        return pts_w

    def _project_points_to_camera(
        self, pts_w: torch.Tensor
    ) -> tuple[torch.Tensor, torch.Tensor, torch.Tensor, torch.Tensor]:
        """world → robot body → camera frame → pinhole → 归一化 → FoV 裁切。

        Returns:
            uv_norm: (N, K, 2) 归一化像素，原始（不强制裁切）
            visible: (N, K) bool
            z_cam:   (N, K) 相机系深度
            pts_b:   (N, K, 3) body frame 坐标（用于 is_near 判定）
        """
        N, K, _ = pts_w.shape
        root_pos = self.robot.data.root_pos_w              # (N, 3)
        root_quat = self.robot.data.root_quat_w            # (N, 4)

        rel_w = pts_w - root_pos.unsqueeze(1)              # (N, K, 3)
        q = root_quat.unsqueeze(1).expand(N, K, 4).reshape(-1, 4)
        pts_b = quat_apply_inverse(q, rel_w.reshape(-1, 3)).reshape(N, K, 3)

        pts_b_off = pts_b - self._geo_cam_pos_body         # (N, K, 3) broadcast

        # body → camera frame: P_c = R · P_b_off
        pts_c = torch.einsum("ij,nkj->nki", self._geo_R_body_cam, pts_b_off)
        x_c = pts_c[..., 0]
        y_c = pts_c[..., 1]
        z_c = pts_c[..., 2]
        z_safe = torch.clamp(z_c, min=1e-3)

        u_pix = self._geo_fx * x_c / z_safe + self._geo_cx
        v_pix = self._geo_fy * y_c / z_safe + self._geo_cy
        u_norm = (u_pix - self._geo_cx) / self._geo_cx
        v_norm = (v_pix - self._geo_cy) / self._geo_cy
        uv_norm = torch.stack([u_norm, v_norm], dim=-1)    # (N, K, 2)

        margin = self._geo_fov_margin
        visible = (z_c > 0.05) & (u_norm.abs() <= margin) & (v_norm.abs() <= margin)
        return uv_norm, visible, z_c, pts_b

    def _get_edge_obs(self) -> torch.Tensor:
        """返回 (N, 12) edge obs：每条短边 6 维 [u1, v1, u2, v2, visible, is_near]。

        - 不可见端点：u=v=0
        - edge_visible：两端点同时可见时为 1
        - is_near：边中点到相机原点（body frame）距离更近的边为 1
        """
        pts_w = self._get_pallet_edges_world()             # (N, 4, 3)
        uv_norm, visible, _z_c, pts_b = self._project_points_to_camera(pts_w)
        # 不可见端点 u=v=0
        uv_norm = uv_norm * visible.unsqueeze(-1).float()  # (N, 4, 2)

        N = pts_w.shape[0]
        uv_e = uv_norm.reshape(N, 2, 2, 2)                 # (N, edge, endpoint, uv)
        vis_e = visible.reshape(N, 2, 2)
        pts_b_e = pts_b.reshape(N, 2, 2, 3)

        edge_vis = vis_e.all(dim=-1).float()               # (N, 2)

        # is_near: 用 argmin 防止两条边并列时同时为 1
        mid_b = pts_b_e.mean(dim=2)                        # (N, 2, 3)
        d2 = ((mid_b - self._geo_cam_pos_body) ** 2).sum(dim=-1)  # (N, 2)
        near_idx = d2.argmin(dim=-1, keepdim=True)         # (N, 1)
        is_near = torch.zeros_like(d2)
        is_near.scatter_(1, near_idx, 1.0)                 # (N, 2)

        u1v1 = uv_e[:, :, 0, :]                            # (N, 2, 2)
        u2v2 = uv_e[:, :, 1, :]                            # (N, 2, 2)
        edge_feat = torch.cat(
            [u1v1, u2v2, edge_vis.unsqueeze(-1), is_near.unsqueeze(-1)],
            dim=-1,
        )                                                  # (N, 2, 6)
        return edge_feat.reshape(N, 12)

    def _get_proprio9(self, insert_norm: torch.Tensor) -> torch.Tensor:
        """Proprio: [v_xy_r (2), yaw_rate (1), lift_pos/scale (1), lift_vel (1),
        insert_norm (1), actions[:, :3] (3)] = 9。"""
        root_quat = self.robot.data.root_quat_w
        root_lin_vel = self.robot.data.root_lin_vel_w
        root_ang_vel = self.robot.data.root_ang_vel_w
        yaw = _quat_to_yaw(root_quat)
        R = _yaw_to_mat2(-yaw)
        v_xy_r = torch.einsum("nij,nj->ni", R, root_lin_vel[:, :2])
        yaw_rate = root_ang_vel[:, 2:3]
        lift_pos = self._joint_pos[:, self._lift_id:self._lift_id + 1] / max(
            float(getattr(self.cfg, "lift_pos_scale", 1.0)), 1e-6
        )
        lift_vel = self._joint_vel[:, self._lift_id:self._lift_id + 1]
        prev_actions = self.actions[:, :3]
        return torch.cat(
            [v_xy_r, yaw_rate, lift_pos, lift_vel, insert_norm.unsqueeze(-1), prev_actions],
            dim=-1,
        )

    def _get_observations_geo_edge(self) -> dict[str, torch.Tensor]:
        """Phase 1A v2 入口：返回 21D 观测 = 12D edge_obs + 9D proprio。"""
        # PhysX 关节刷新（与 _get_observations 同步处理逻辑）
        self._joint_pos[:] = self.robot.root_physx_view.get_dof_positions()
        self._joint_vel[:] = self.robot.root_physx_view.get_dof_velocities()

        # insert_norm 计算（与 _get_observations 同源几何，pallet local frame 投影）
        pallet_pos = self.pallet.data.root_pos_w
        pallet_quat = self.pallet.data.root_quat_w
        pallet_yaw = _quat_to_yaw(pallet_quat)
        cp_obs = torch.cos(pallet_yaw)
        sp_obs = torch.sin(pallet_yaw)
        u_in_obs = torch.stack([cp_obs, sp_obs], dim=-1)
        tip = self._compute_fork_tip()
        rel_tip_obs = tip[:, :2] - pallet_pos[:, :2]
        s_tip_obs = torch.sum(rel_tip_obs * u_in_obs, dim=-1)
        s_front_obs = -0.5 * self.cfg.pallet_depth_m
        insert_depth_obs = torch.clamp(s_tip_obs - s_front_obs, min=0.0)

        lift_height_obs = tip[:, 2] - self._fork_tip_z0
        pallet_lift_height_obs = pallet_pos[:, 2] - self.cfg.pallet_cfg.init_state.pos[2]
        z_err_obs = torch.abs(lift_height_obs - pallet_lift_height_obs)
        valid_insert_z_obs = z_err_obs < self.cfg.max_insert_z_err
        insert_depth_obs = torch.where(
            valid_insert_z_obs, insert_depth_obs, torch.zeros_like(insert_depth_obs)
        )
        insert_norm = torch.clamp(
            insert_depth_obs / (self.cfg.pallet_depth_m + 1e-6), 0.0, 1.0
        )

        edge_obs = self._get_edge_obs()              # (N, 12)
        proprio = self._get_proprio9(insert_norm)    # (N, 9)
        obs21 = torch.cat([edge_obs, proprio], dim=-1)  # (N, 21)

        return {"policy": obs21}

    # ==========================================================================
    #  Easy8 / Privileged / 主观测入口
    # ==========================================================================
    def _get_easy8(self) -> torch.Tensor:
        """提取 easy8: [v_x_r, v_y_r, yaw_rate, lift_pos, lift_vel, prev_drive, prev_steer, prev_lift]"""
        root_quat = self.robot.data.root_quat_w
        root_lin_vel = self.robot.data.root_lin_vel_w
        root_ang_vel = self.robot.data.root_ang_vel_w
        yaw = _quat_to_yaw(root_quat)
        R = _yaw_to_mat2(-yaw)
        v_xy_r = torch.einsum("nij,nj->ni", R, root_lin_vel[:, :2])
        yaw_rate = root_ang_vel[:, 2:3]
        lift_pos = self._joint_pos[:, self._lift_id:self._lift_id + 1] / max(float(getattr(self.cfg, "lift_pos_scale", 1.0)), 1e-6)
        lift_vel = self._joint_vel[:, self._lift_id:self._lift_id + 1]
        prev_actions = self.actions[:, :3]
        return torch.cat([v_xy_r, yaw_rate, lift_pos, lift_vel, prev_actions], dim=-1)

    def _get_privileged_obs(self, policy_obs: torch.Tensor) -> torch.Tensor:
        """返回 critic 使用的 15 维低维状态。"""
        return policy_obs

    def _get_observations(self) -> dict[str, torch.Tensor]:
        """构造观测向量（长度=15，S1.0N: 13→15）。

        顺序如下：
        1) 机器人到托盘的相对位置（机器人坐标系）d_xy_r (2)
        2) 偏航差 dyaw 的 cos/sin (2)
        3) 机器人线速度（机器人坐标系）v_xy_r (2)
        4) 机器人偏航角速度 yaw_rate (1)
        5) lift 关节位置与速度 (2)
        6) 插入深度归一化 insert_norm (1)
        7) 当前动作 actions (3)
        8) S1.0N: pallet center line frame 横向误差 y_err_obs (1, 带符号, clip [-1,1])
        9) S1.0N: pallet center line frame 偏航误差 yaw_err_obs (1, 带符号, clip [-1,1])

        Phase 1A v2: 当 self._geo_edge_enabled 时，改返回 21D 几何边缘观测
        (12 维 edge_obs + 9 维 proprio)。
        """
        if self._geo_edge_enabled:
            return self._get_observations_geo_edge()
        # ---- 从 PhysX view 刷新关节数据 ----
        # robot.data.joint_pos 在 Fabric clone 失败时不更新（始终为 0），
        # 但 root_physx_view.get_dof_positions() 能正确返回值。
        self._joint_pos[:] = self.robot.root_physx_view.get_dof_positions()
        self._joint_vel[:] = self.robot.root_physx_view.get_dof_velocities()

        # ---- PhysX 直读诊断 ----
        # 条件1: 前 5 步（初始化阶段）
        # 条件2: lift_target > 0 的前 10 次（举升阶段）
        _diag_init = self.common_step_counter < 5
        _diag_lift = (self._lift_pos_target[0] > 0.001
                      and not hasattr(self, '_diag_lift_count'))
        _diag_lift_ongoing = (self._lift_pos_target[0] > 0.001
                              and hasattr(self, '_diag_lift_count')
                              and self._diag_lift_count < 10
                              and self.common_step_counter % 20 == 0)
        if _diag_init or _diag_lift or _diag_lift_ongoing:
            if _diag_lift and not hasattr(self, '_diag_lift_count'):
                self._diag_lift_count = 0
            try:
                dof_pos = self.robot.root_physx_view.get_dof_positions()
                dof_vel = self.robot.root_physx_view.get_dof_velocities()
                print(f"[DIAG step={self.common_step_counter}] "
                      f"physx.dof_pos(lift)={dof_pos[0, self._lift_id]:.5f}, "
                      f"physx.dof_vel(lift)={dof_vel[0, self._lift_id]:.5f}, "
                      f"lab.joint_pos={self._joint_pos[0, self._lift_id]:.5f}, "
                      f"lift_target={self._lift_pos_target[0]:.5f}")
                if hasattr(self, '_diag_lift_count'):
                    self._diag_lift_count += 1
            except Exception as e:
                print(f"[DIAG step={self.common_step_counter}] PhysX 直读失败: {e}")

        # states
        root_pos = self.robot.data.root_pos_w
        root_quat = self.robot.data.root_quat_w
        root_lin_vel = self.robot.data.root_lin_vel_w
        root_ang_vel = self.robot.data.root_ang_vel_w

        yaw = _quat_to_yaw(root_quat)
        R = _yaw_to_mat2(-yaw)  # world->robot 2D

        pallet_pos = self.pallet.data.root_pos_w
        pallet_quat = self.pallet.data.root_quat_w
        pallet_yaw = _quat_to_yaw(pallet_quat)

        # relative position in world
        d_xy_w = (pallet_pos[:, :2] - root_pos[:, :2])
        d_xy_r = torch.einsum("nij,nj->ni", R, d_xy_w)

        dyaw = pallet_yaw - yaw
        cos_dyaw = torch.cos(dyaw)
        sin_dyaw = torch.sin(dyaw)

        # velocities in robot frame
        v_xy_w = root_lin_vel[:, :2]
        v_xy_r = torch.einsum("nij,nj->ni", R, v_xy_w)
        yaw_rate = root_ang_vel[:, 2:3]

        lift_pos = self._joint_pos[:, self._lift_id:self._lift_id + 1]
        lift_vel = self._joint_vel[:, self._lift_id:self._lift_id + 1]

        # insertion depth (normalized)
        # S1.0W: 修复观测坐标系与奖励计算不一致的问题 (Bug 1)。使用托盘局部坐标系投影。
        tip = self._compute_fork_tip()
        cp_obs = torch.cos(pallet_yaw)
        sp_obs = torch.sin(pallet_yaw)
        u_in_obs = torch.stack([cp_obs, sp_obs], dim=-1)
        rel_tip_obs = tip[:, :2] - pallet_pos[:, :2]
        s_tip_obs = torch.sum(rel_tip_obs * u_in_obs, dim=-1)
        s_front_obs = -0.5 * self.cfg.pallet_depth_m
        insert_depth_obs = torch.clamp(s_tip_obs - s_front_obs, min=0.0)
        
        # 新增 Z 轴对齐约束（防止隔空飞越作弊）
        lift_height_obs = tip[:, 2] - self._fork_tip_z0
        pallet_lift_height_obs = pallet_pos[:, 2] - self.cfg.pallet_cfg.init_state.pos[2]
        z_err_obs = torch.abs(lift_height_obs - pallet_lift_height_obs)
        valid_insert_z_obs = z_err_obs < self.cfg.max_insert_z_err
        insert_depth_obs = torch.where(valid_insert_z_obs, insert_depth_obs, torch.zeros_like(insert_depth_obs))
        
        insert_norm = torch.clamp(
            insert_depth_obs / (self.cfg.pallet_depth_m + 1e-6), 0.0, 1.0
        ).unsqueeze(-1)

        # S1.0N: pallet center line frame 误差（与 _get_rewards 同源几何）
        v_lat_obs = torch.stack([-sp_obs, cp_obs], dim=-1)
        y_signed_obs = torch.sum((root_pos[:, :2] - pallet_pos[:, :2]) * v_lat_obs, dim=-1)
        # S1.0S Phase-0.5: 使用可配置尺度替代硬编码 0.5（消除 |y|>scale 时观测饱和）
        y_err_obs = torch.clamp(y_signed_obs / self.cfg.y_err_obs_scale, -1.0, 1.0)

        dyaw_signed_obs = torch.atan2(torch.sin(yaw - pallet_yaw), torch.cos(yaw - pallet_yaw))
        yaw_err_obs = torch.clamp(dyaw_signed_obs / (15.0 * math.pi / 180.0), -1.0, 1.0)

        obs = torch.cat(
            [
                d_xy_r,  # 2
                cos_dyaw.unsqueeze(-1), sin_dyaw.unsqueeze(-1),  # 2
                v_xy_r,  # 2
                yaw_rate,  # 1
                lift_pos / self.cfg.lift_pos_scale, lift_vel,  # 2  S1.0T: obs 归一化
                insert_norm,  # 1
                self.actions,  # 3
                y_err_obs.unsqueeze(-1),    # 1 — S1.0N
                yaw_err_obs.unsqueeze(-1),  # 1 — S1.0N
            ],
            dim=-1,
        )
        # Isaac Lab direct workflow expects a dict with at least the "policy" key.
        if self._camera_enabled:
            image = self._get_camera_image()
            proprio = self._get_easy8()
            obs_dict: dict[str, torch.Tensor | dict[str, torch.Tensor]] = {
                "policy": {
                    "image": image,
                    "proprio": proprio,
                },
                # rsl_rl 的 obs_groups / rollout storage 在 update 阶段直接按顶层 group 取值，
                # 因此这里显式暴露 image/proprio，避免只在 reset 阶段能访问嵌套结构。
                "image": image,
                "proprio": proprio,
            }
        else:
            obs_dict = {"policy": obs}

        if self._asym_enabled:
            obs_dict["critic"] = self._get_privileged_obs(obs)

        return obs_dict

    def _get_rewards(self) -> torch.Tensor:
        """实验 B: 去过度设计版论文原生 Reward"""
        # ---- 从 PhysX view 刷新关节数据 ----
        self._joint_pos[:] = self.robot.root_physx_view.get_dof_positions()
        self._joint_vel[:] = self.robot.root_physx_view.get_dof_velocities()

        # ---- 基础量 ----
        root_pos = self.robot.data.root_pos_w
        pallet_pos = self.pallet.data.root_pos_w
        tip = self._compute_fork_tip()                                       # (N, 3)
        fork_center = self._compute_fork_center()                            # (N, 3)

        robot_yaw = _quat_to_yaw(self.robot.data.root_quat_w)               # (N,)
        pallet_yaw = _quat_to_yaw(self.pallet.data.root_quat_w)             # (N,)
        
        # 偏航误差（中心线平行度）
        yaw_err = torch.atan2(
            torch.sin(robot_yaw - pallet_yaw),
            torch.cos(robot_yaw - pallet_yaw),
        )
        yaw_err_deg = torch.abs(yaw_err) * (180.0 / math.pi)
        yaw_err_rad = torch.abs(yaw_err)

        # ---- 严格中心线几何 ----
        cp = torch.cos(pallet_yaw)
        sp = torch.sin(pallet_yaw)
        u_in = torch.stack([cp, sp], dim=-1)                                 # (N,2) 插入方向
        v_lat = torch.stack([-sp, cp], dim=-1)                               # (N,2) 横向

        # 横向误差（中心线重叠度）
        rel_robot = root_pos[:, :2] - pallet_pos[:, :2]
        y_signed = torch.sum(rel_robot * v_lat, dim=-1)
        y_err = torch.abs(y_signed)

        # S1.0U: fork tip 在 pallet center-line frame 中的横向误差
        rel_tip_lat = tip[:, :2] - pallet_pos[:, :2]
        tip_y_signed = torch.sum(rel_tip_lat * v_lat, dim=-1)
        tip_y_err = torch.abs(tip_y_signed)

        # 举升
        lift_height = tip[:, 2] - self._fork_tip_z0
        pallet_lift_height = pallet_pos[:, 2] - self.cfg.pallet_cfg.init_state.pos[2]
        z_err = torch.abs(lift_height - pallet_lift_height)
        valid_insert_z = z_err < self.cfg.max_insert_z_err

        # 沿托盘插入轴的标量坐标
        rel_tip = tip[:, :2] - pallet_pos[:, :2]
        s_tip = torch.sum(rel_tip * u_in, dim=-1)
        s_front = -0.5 * self.cfg.pallet_depth_m

        dist_front = torch.clamp(s_front - s_tip, min=0.0)
        insert_depth = torch.clamp(s_tip - s_front, min=0.0)

        # 仍需 insert_depth 用于 _apply_action 安全制动
        self._last_insert_depth = insert_depth.detach()

        # ---- 成功/hold 诊断口径（fork center frame）----
        rel_fc = fork_center[:, :2] - pallet_pos[:, :2]
        center_y_err = torch.abs(torch.sum(rel_fc * v_lat, dim=-1))
        strict_tip_gate_m = float(getattr(self.cfg, "strict_tip_align_entry_m", 0.12))
        curriculum_progress = 1.0
        if self.cfg.hold_gate_curriculum_enable:
            curriculum_steps = max(1, int(self.cfg.hold_gate_curriculum_steps))
            curriculum_progress = min(1.0, float(self.common_step_counter) / float(curriculum_steps))
            training_tip_gate_m = (
                float(self.cfg.hold_gate_curriculum_start_m)
                + (
                    float(self.cfg.hold_gate_curriculum_end_m)
                    - float(self.cfg.hold_gate_curriculum_start_m)
                )
                * curriculum_progress
            )
        else:
            training_tip_gate_m = float(self.cfg.tip_align_entry_m)
        training_tip_gate_m = max(0.0, training_tip_gate_m)
        training_tip_exit_m = max(float(self.cfg.tip_align_exit_m), training_tip_gate_m)

        hold_logic_cfg = HoldLogicConfig(
            insert_thresh=self._insert_thresh,
            max_lateral_err_m=self.cfg.max_lateral_err_m,
            max_yaw_err_deg=self.cfg.max_yaw_err_deg,
            hysteresis_ratio=self.cfg.hysteresis_ratio,
            insert_exit_epsilon=self.cfg.insert_exit_epsilon,
            lift_delta_m=self.cfg.lift_delta_m,
            lift_exit_epsilon=self.cfg.lift_exit_epsilon,
            hold_counter_decay=self.cfg.hold_counter_decay,
            tip_align_entry_m=training_tip_gate_m,
            tip_align_exit_m=training_tip_exit_m,
            tip_align_near_dist=self.cfg.tip_align_near_dist,
            require_lift=not (self._stage_1_mode and self.cfg.stage1_success_without_lift),
        )
        hold_state = compute_hold_logic(
            center_y_err=center_y_err,
            yaw_err_deg=yaw_err_deg,
            insert_depth=insert_depth,
            lift_height=lift_height,
            tip_y_err=tip_y_err,
            dist_front=dist_front,
            hold_counter=self._hold_counter,
            cfg=hold_logic_cfg,
        )
        strict_hold_logic_cfg = HoldLogicConfig(
            insert_thresh=self._insert_thresh,
            max_lateral_err_m=self.cfg.max_lateral_err_m,
            max_yaw_err_deg=self.cfg.max_yaw_err_deg,
            hysteresis_ratio=self.cfg.hysteresis_ratio,
            insert_exit_epsilon=self.cfg.insert_exit_epsilon,
            lift_delta_m=self.cfg.lift_delta_m,
            lift_exit_epsilon=self.cfg.lift_exit_epsilon,
            hold_counter_decay=self.cfg.hold_counter_decay,
            tip_align_entry_m=strict_tip_gate_m,
            tip_align_exit_m=max(float(self.cfg.tip_align_exit_m), strict_tip_gate_m),
            tip_align_near_dist=self.cfg.tip_align_near_dist,
            require_lift=not (self._stage_1_mode and self.cfg.stage1_success_without_lift),
        )
        strict_hold_state = compute_hold_logic(
            center_y_err=center_y_err,
            yaw_err_deg=yaw_err_deg,
            insert_depth=insert_depth,
            lift_height=lift_height,
            tip_y_err=tip_y_err,
            dist_front=dist_front,
            hold_counter=self._hold_counter,
            cfg=strict_hold_logic_cfg,
        )
        success_geom_strict = (
            strict_hold_state.insert_entry
            & valid_insert_z
            & strict_hold_state.align_entry
            & strict_hold_state.tip_entry
        )
        success_geom_training = (
            hold_state.insert_entry
            & valid_insert_z
            & hold_state.align_entry
            & hold_state.tip_entry
        )
        lifted_enough = lift_height >= self.cfg.lift_delta_m
        success_strict = success_geom_strict & lifted_enough
        time_out = self.episode_length_buf >= self.max_episode_length - 1

        # ---- 实验 B: 论文原生 Reward 计算 ----
        
        # 2. 距离 rd 的定义：叉臂中心到当前 family target_center 的距离
        pallet_yaw = _quat_to_yaw(self.pallet.data.root_quat_w)
        dist_center_family, _ = self._exp83_target_center_family_dist(
            fork_center[:, :2], pallet_pos[:, :2], pallet_yaw
        )
        insert_norm = torch.clamp(insert_depth / (self.cfg.pallet_depth_m + 1e-6), 0.0, 1.0)
        pallet_init_pos_xy = torch.tensor(self.cfg.pallet_cfg.init_state.pos[:2], device=self.device)
        pallet_disp_xy = torch.norm(pallet_pos[:, :2] - pallet_init_pos_xy, dim=-1)
        push_free = pallet_disp_xy < self.cfg.push_free_disp_thresh_m
        inserted_push_free_reward = hold_state.hold_entry & push_free  # O2b: was (insert_depth >= self._insert_thresh)
        training_success_next = hold_state.hold_counter_next >= self._hold_steps
        if self.cfg.push_free_training_success_enable:
            success_next = training_success_next & push_free
        else:
            success_next = training_success_next

        use_reference_trajectory = bool(getattr(self.cfg, "use_reference_trajectory", True))
        if use_reference_trajectory:
            d_traj, yaw_traj_err_deg, _ = self._query_reference_trajectory()
            yaw_traj_err_rad = yaw_traj_err_deg * (math.pi / 180.0)
            r_cd_raw = torch.clip(1.0 / (d_traj + 1e-5), 0.0, self.cfg.paper_reward_max)
            r_cpsi_raw = torch.clip(1.0 / (yaw_traj_err_rad + 1e-5), 0.0, self.cfg.paper_reward_max)
        else:
            d_traj = torch.zeros_like(dist_front)
            yaw_traj_err_deg = torch.zeros_like(dist_front)
            yaw_traj_err_rad = torch.zeros_like(dist_front)
            r_cd_raw = torch.zeros_like(dist_front)
            r_cpsi_raw = torch.zeros_like(dist_front)

        # 3. 正向奖励 R+ (使用 exp 替代 1/x 防止数值爆炸)
        # 论文原生 1/x 形式，使用 clip 防止近场爆炸，释放远场原生引力
        r_d_raw = torch.clip(1.0 / (dist_center_family + 1e-5), 0.0, self.cfg.paper_reward_max)

        if self.cfg.clean_insert_reward_gate_enable:
            clean_insert_progress = smoothstep(
                (insert_norm - self.cfg.clean_insert_gate_start_frac)
                / max(self.cfg.clean_insert_gate_ramp_frac, 1e-6)
            )
            clean_center_gate = torch.exp(
                -(center_y_err / max(self.cfg.clean_insert_center_sigma_m, 1e-6)) ** 2
            )
            clean_yaw_gate = torch.exp(
                -(yaw_err_deg / max(self.cfg.clean_insert_yaw_sigma_deg, 1e-6)) ** 2
            )
            clean_tip_gate = torch.where(
                dist_front <= self.cfg.tip_align_near_dist,
                torch.exp(
                    -(tip_y_err / max(self.cfg.clean_insert_tip_sigma_m, 1e-6)) ** 2
                ),
                torch.ones_like(tip_y_err),
            )
            clean_align_gate = clean_center_gate * clean_yaw_gate * clean_tip_gate
            if self.cfg.clean_insert_use_push_gate:
                clean_push_gate = torch.exp(
                    -(pallet_disp_xy / max(self.cfg.clean_insert_push_sigma_m, 1e-6)) ** 2
                )
            else:
                clean_push_gate = torch.ones_like(clean_align_gate)

            clean_insert_gate_core = clean_align_gate * clean_push_gate

            clean_insert_gate = 1.0 - clean_insert_progress + clean_insert_progress * (
                self.cfg.clean_insert_gate_floor
                + (1.0 - self.cfg.clean_insert_gate_floor) * clean_insert_gate_core
            )
        else:
            clean_insert_progress = torch.zeros_like(insert_norm)
            clean_center_gate = torch.ones_like(insert_norm)
            clean_yaw_gate = torch.ones_like(insert_norm)
            clean_tip_gate = torch.ones_like(insert_norm)
            clean_push_gate = torch.ones_like(insert_norm)
            clean_align_gate = torch.ones_like(insert_norm)
            clean_insert_gate = torch.ones_like(insert_norm)

        if self.cfg.preinsert_contact_clean_gate_enable:
            contact_dist_gate = smoothstep(
                (self.cfg.preinsert_contact_dist_m + self.cfg.preinsert_contact_dist_ramp_m - dist_front)
                / max(self.cfg.preinsert_contact_dist_ramp_m, 1e-6)
            )
            contact_insert_gate = (insert_norm < self.cfg.preinsert_contact_insert_frac_max).float()
            preinsert_contact_active = contact_dist_gate * contact_insert_gate
            contact_center_gate = torch.exp(
                -(center_y_err / max(self.cfg.preinsert_contact_center_sigma_m, 1e-6)) ** 2
            )
            contact_yaw_gate = torch.exp(
                -(yaw_err_deg / max(self.cfg.preinsert_contact_yaw_sigma_deg, 1e-6)) ** 2
            )
            contact_tip_gate = torch.where(
                dist_front <= self.cfg.tip_align_near_dist,
                torch.exp(
                    -(tip_y_err / max(self.cfg.preinsert_contact_tip_sigma_m, 1e-6)) ** 2
                ),
                torch.ones_like(tip_y_err),
            )
            preinsert_contact_clean_gate = (
                self.cfg.preinsert_contact_gate_floor
                + (1.0 - self.cfg.preinsert_contact_gate_floor)
                * contact_center_gate
                * contact_yaw_gate
                * contact_tip_gate
            )
            preinsert_reward_gate = (
                1.0
                - preinsert_contact_active
                + preinsert_contact_active * preinsert_contact_clean_gate
            )
            proj_vel_forward = torch.clamp(
                torch.sum(self.robot.data.root_vel_w[:, :2] * u_in, dim=-1),
                min=0.0,
            )
            r_preinsert_contact_drive = -(
                self.cfg.preinsert_contact_drive_penalty_weight
                * preinsert_contact_active
                * (1.0 - preinsert_contact_clean_gate)
                * torch.clamp(
                    proj_vel_forward
                    / max(self.cfg.preinsert_contact_drive_vel_scale_mps, 1e-6),
                    min=0.0,
                    max=1.0,
                )
            )
        else:
            preinsert_contact_active = torch.zeros_like(insert_norm)
            preinsert_contact_clean_gate = torch.ones_like(insert_norm)
            preinsert_reward_gate = torch.ones_like(insert_norm)
            r_preinsert_contact_drive = torch.zeros_like(insert_norm)

        r_d = r_d_raw * clean_insert_gate
        r_cd = r_cd_raw * clean_insert_gate if self.cfg.clean_insert_gate_r_cd else r_cd_raw
        r_cpsi = (
            r_cpsi_raw * clean_insert_gate
            if self.cfg.clean_insert_gate_r_cpsi
            else r_cpsi_raw
        )
        if self.cfg.preinsert_contact_gate_r_d:
            r_d = r_d * preinsert_reward_gate
        if self.cfg.preinsert_contact_gate_r_cd:
            r_cd = r_cd * preinsert_reward_gate
        if self.cfg.preinsert_contact_gate_r_cpsi:
            r_cpsi = r_cpsi * preinsert_reward_gate

        if self.cfg.clean_insert_dirty_penalty_enable:
            r_dirty_insert = -self.cfg.clean_insert_dirty_penalty_weight * clean_insert_progress * (
                1.0 - clean_push_gate
            )
        else:
            r_dirty_insert = torch.zeros_like(clean_insert_progress)

        if self.cfg.push_free_training_success_enable:
            r_dirty_success = -(
                self.cfg.push_free_dirty_success_penalty_weight
                * training_success_next.float()
                * (~push_free).float()
            )
        else:
            r_dirty_success = torch.zeros_like(clean_insert_progress)

        if self.cfg.clean_insert_push_free_bonus_enable:
            r_clean_insert_bonus = (
                self.cfg.clean_insert_push_free_bonus_weight
                * inserted_push_free_reward.float()
            )
        else:
            r_clean_insert_bonus = torch.zeros_like(clean_insert_progress)

        if self.cfg.preinsert_align_reward_enable:
            preinsert_dist_gate = smoothstep(
                (self.cfg.preinsert_active_dist_max_m - dist_front)
                / max(self.cfg.preinsert_active_dist_ramp_m, 1e-6)
            )
            preinsert_insert_gate = (insert_norm < self.cfg.preinsert_insert_frac_max).float()
            preinsert_active = preinsert_dist_gate * preinsert_insert_gate

            y_delta = torch.clamp(
                self._prev_y_err - y_err,
                min=-self.cfg.preinsert_delta_clip_y_m,
                max=self.cfg.preinsert_delta_clip_y_m,
            )
            yaw_delta = torch.clamp(
                self._prev_yaw_err_deg - yaw_err_deg,
                min=-self.cfg.preinsert_delta_clip_yaw_deg,
                max=self.cfg.preinsert_delta_clip_yaw_deg,
            )
            dist_delta = torch.clamp(
                self._prev_dist_front - dist_front,
                min=-self.cfg.preinsert_delta_clip_dist_m,
                max=self.cfg.preinsert_delta_clip_dist_m,
            )

            y_delta_pos = torch.clamp(
                y_delta / max(self.cfg.preinsert_delta_clip_y_m, 1e-6), min=0.0, max=1.0
            )
            yaw_delta_pos = torch.clamp(
                yaw_delta / max(self.cfg.preinsert_delta_clip_yaw_deg, 1e-6), min=0.0, max=1.0
            )
            dist_delta_pos = torch.clamp(
                dist_delta / max(self.cfg.preinsert_delta_clip_dist_m, 1e-6), min=0.0, max=1.0
            )
            retreat_delta = torch.clamp(
                -dist_delta / max(self.cfg.preinsert_delta_clip_dist_m, 1e-6), min=0.0, max=1.0
            )

            r_preinsert_align = preinsert_active * (
                self.cfg.preinsert_y_err_delta_weight * y_delta_pos
                + self.cfg.preinsert_yaw_err_delta_weight * yaw_delta_pos
                + self.cfg.preinsert_dist_front_delta_weight * dist_delta_pos
            )
            r_preinsert_retreat = -preinsert_active * (
                self.cfg.preinsert_retreat_penalty_weight * retreat_delta
            )
        else:
            preinsert_active = torch.zeros_like(insert_norm)
            y_delta = torch.zeros_like(y_err)
            yaw_delta = torch.zeros_like(yaw_err_deg)
            dist_delta = torch.zeros_like(dist_front)
            r_preinsert_align = torch.zeros_like(insert_norm)
            r_preinsert_retreat = torch.zeros_like(insert_norm)

        if self.cfg.preinsert_push_penalty_enable:
            preinsert_push_amount = torch.clamp(
                (pallet_disp_xy - self.cfg.preinsert_push_penalty_start_m)
                / max(self.cfg.preinsert_push_penalty_scale_m, 1e-6),
                min=0.0,
                max=1.0,
            )
            r_preinsert_push = -(
                self.cfg.preinsert_push_penalty_weight
                * preinsert_active
                * preinsert_push_amount
            )
        else:
            r_preinsert_push = torch.zeros_like(insert_norm)

        if self.cfg.preinsert_push_termination_enable:
            preinsert_push_termination = self._preinsert_push_termination
            r_preinsert_push_termination = -(
                self.cfg.preinsert_push_termination_penalty_weight
                * preinsert_push_termination.float()
            )
        else:
            preinsert_push_termination = torch.zeros_like(success_next, dtype=torch.bool)
            r_preinsert_push_termination = torch.zeros_like(insert_norm)

        # O2/O3: post-insert lateral/tip/yaw dense shaping
        if self.cfg.postinsert_align_enable:
            postinsert_active = (insert_depth >= self._insert_thresh).float()
            center_y_shaping = torch.exp(
                -(center_y_err / max(self.cfg.postinsert_center_sigma_m, 1e-6)) ** 2
            )
            tip_y_shaping = torch.where(
                dist_front <= self.cfg.tip_align_near_dist,
                torch.exp(
                    -(tip_y_err / max(self.cfg.postinsert_tip_sigma_m, 1e-6)) ** 2
                ),
                torch.ones_like(tip_y_err),
            )
            yaw_shaping = torch.exp(
                -(yaw_err_deg / max(self.cfg.postinsert_yaw_sigma_deg, 1e-6)) ** 2
            )
            r_postinsert_align = postinsert_active * self.cfg.postinsert_align_weight * (
                self.cfg.postinsert_center_weight * center_y_shaping
                + self.cfg.postinsert_tip_weight * tip_y_shaping
                + self.cfg.postinsert_yaw_weight * yaw_shaping
            )
        else:
            r_postinsert_align = torch.zeros_like(insert_norm)

        # rg: training-time arrival geometry. With the curriculum disabled this
        # is identical to the strict diagnostic geometry.
        rg = success_geom_training.float()

        # r_lift: 举升奖励 (纯 approach 阶段设为 0)
        lift_height_joint = self._joint_pos[:, self._lift_id]
        r_lift = rg * lift_height_joint * self.cfg.alpha_lift

        lift_delta = torch.clamp(lift_height - self._prev_lift_height, min=0.0)
        lift_progress_norm = torch.clamp(
            lift_delta / max(float(self.cfg.lift_progress_reward_scale_m), 1e-6),
            min=0.0,
            max=1.0,
        )
        lift_reward_geom_gate = success_geom_strict.float()
        if self.cfg.lift_progress_reward_enable:
            r_lift_progress = (
                self.cfg.lift_progress_reward_weight
                * lift_reward_geom_gate
                * lift_progress_norm
            )
        else:
            r_lift_progress = torch.zeros_like(insert_norm)

        if self.cfg.hold_counter_progress_reward_enable:
            hold_counter_delta = torch.clamp(
                hold_state.hold_counter_next - self._hold_counter,
                min=0.0,
            )
            r_hold_counter_progress = (
                self.cfg.hold_counter_progress_reward_weight
                * torch.clamp(hold_counter_delta / float(self._hold_steps), min=0.0, max=1.0)
            )
        else:
            hold_counter_delta = torch.zeros_like(insert_norm)
            r_hold_counter_progress = torch.zeros_like(insert_norm)

        if self.cfg.premature_lift_penalty_enable:
            premature_lift_amount = torch.clamp(
                lift_height - float(self.cfg.premature_lift_penalty_deadband_m),
                min=0.0,
            )
            r_premature_lift = -(
                self.cfg.premature_lift_penalty_weight
                * (~success_geom_strict).float()
                * premature_lift_amount
            )
        else:
            r_premature_lift = torch.zeros_like(insert_norm)

        if self.cfg.post_lift_stability_penalty_enable:
            post_lift_active = (lift_height >= self.cfg.post_lift_stability_min_lift_m).float()
            drive_steer_mag = torch.norm(self.actions[:, :2], dim=-1)
            r_post_lift_stability = -(
                self.cfg.post_lift_stability_penalty_weight
                * post_lift_active
                * drive_steer_mag
            )
        else:
            post_lift_active = torch.zeros_like(insert_norm)
            r_post_lift_stability = torch.zeros_like(insert_norm)

        # 动态放大近处的对齐奖励权重 (dist_front < 0.5m 时放大 3 倍)
        alpha_3_dynamic = torch.where(dist_front < 0.5, self.cfg.alpha_3 * 3.0, self.cfg.alpha_3)

        R_plus = (
            self.cfg.alpha_1 * r_d +
            self.cfg.alpha_2 * r_cd +
            alpha_3_dynamic * r_cpsi +
            self.cfg.alpha_4 * rg +
            r_lift +
            r_lift_progress +
            r_hold_counter_progress +
            r_clean_insert_bonus +
            r_preinsert_align +
            r_postinsert_align
        )
        
        # 3. 负向惩罚 R- (Eq.7)
        # rp: 托盘移动惩罚
        pallet_vel_xy = torch.norm(self.pallet.data.root_vel_w[:, :2], dim=-1)
        rp = torch.where(pallet_vel_xy > self.cfg.paper_pallet_vel_thresh, -1.0, 0.0)
        
        # rv: 叉车超速惩罚
        fork_vel_xy = torch.norm(self.robot.data.root_vel_w[:, :2], dim=-1)
        rv = torch.where(
            fork_vel_xy > self.cfg.paper_fork_vel_thresh,
            -(fork_vel_xy - self.cfg.paper_fork_vel_thresh) ** 2,
            0.0
        )
        
        # ra: 动作突变惩罚
        ra = -torch.norm(self.actions - self.previous_actions, dim=-1) ** 2
        
        # r_bound: 动作均值边界惩罚 (替代论文中的 L_bound 损失)
        # 论文中 L_bound = ||mu(o_t)||，我们在这里用 ||a|| 作为 reward 惩罚，起到相同的正则化效果
        r_bound = -torch.norm(self.actions, dim=-1)
        
        # rini: 初始停滞惩罚 (已修复: proj_vel < 0.05 且 dist_front > 0.3)
        fork_vel_xy_vec = self.robot.data.root_vel_w[:, :2]
        proj_vel = torch.sum(fork_vel_xy_vec * u_in, dim=-1)
        rini = torch.where(
            (proj_vel < self.cfg.paper_ini_vel_thresh) & (dist_front > self.cfg.paper_ini_dist_thresh),
            -1.0,
            0.0
        )

        # r_out: 越界逃跑惩罚
        r_out = torch.where(
            dist_front > self.cfg.paper_out_of_bounds_dist,
            -1.0,
            0.0
        )

        R_minus = (
            self.cfg.alpha_5 * rp +
            self.cfg.alpha_6 * rv +
            self.cfg.alpha_7 * ra +
            self.cfg.alpha_bound * r_bound +
            self.cfg.alpha_8 * rini +
            self.cfg.alpha_9 * r_out +
            r_dirty_insert +
            r_dirty_success +
            r_preinsert_retreat +
            r_preinsert_push +
            r_preinsert_push_termination +
            r_preinsert_contact_drive +
            r_premature_lift +
            r_post_lift_stability
        )

        r_success = success_next.float() * self.cfg.rew_success
        r_success_time = success_next.float() * self.cfg.rew_success_time
        r_timeout = (~success_next & time_out).float() * self.cfg.rew_timeout

        # 4. 总奖励
        rew = R_plus + R_minus + r_success + r_success_time + r_timeout
        
        # 清除首步标记
        self._is_first_step[:] = False

        # ==================================================================
        # 状态更新与日志输出
        # ==================================================================
        
        # 更新持有时长计数器 (用于 success 判断)
        self._hold_counter = hold_state.hold_counter_next
        self._last_hold_entry = hold_state.hold_entry
        self._success_termination = success_next

        # 仅做诊断：更严格的成功口径，不改变当前训练正在使用的 success / done。
        is_inserted = hold_state.insert_entry
        is_inserted_z_valid = is_inserted & valid_insert_z
        is_center_aligned_cfg = hold_state.align_entry
        is_near_field = hold_state.tip_gate_active
        is_tip_aligned_near = hold_state.tip_gate_active & hold_state.tip_entry
        is_tip_constraint_ok = hold_state.tip_entry
        is_aligned = hold_state.align_entry
        
        # 与 _get_dones 共用的终止掩码（用于 Exp8.3 诊断日志）
        tipped, success, out_of_bounds = self._termination_masks()

        # 记录 push-free success (成功且托盘位移小)
        push_free_success_strict = success_strict & push_free
        max_hold_counter = self._hold_counter.max()

        def _masked_mean(values: torch.Tensor, mask: torch.Tensor) -> torch.Tensor:
            mask_f = mask.float()
            return torch.sum(values * mask_f) / mask_f.sum().clamp_min(1.0)

        inserted_push_free = is_inserted & push_free
        clean_insert_ready = is_inserted & is_center_aligned_cfg & is_tip_constraint_ok & push_free
        dirty_insert = is_inserted & ~push_free
        prehold_reachable_common = (
            is_inserted
            & is_center_aligned_cfg
            & hold_state.lift_entry
            & valid_insert_z
            & hold_state.tip_gate_active
        )
        prehold_reachable_strict_ref = (
            prehold_reachable_common
            & (tip_y_err <= self.cfg.prehold_reachable_strict_tip_ref_m)
        )
        prehold_reachable_band = (
            prehold_reachable_common
            & (tip_y_err <= self.cfg.prehold_reachable_tip_band_m)
            & (~prehold_reachable_strict_ref)
        )
        prehold_reachable_band_companion = (
            prehold_reachable_common
            & (tip_y_err <= self.cfg.prehold_reachable_tip_band_companion_m)
            & (~prehold_reachable_strict_ref)
        )
        inserted_center_lateral_mean = _masked_mean(center_y_err, is_inserted)
        inserted_tip_lateral_mean = _masked_mean(tip_y_err, is_inserted)
        inserted_yaw_deg_mean = _masked_mean(yaw_err_deg, is_inserted)
        inserted_pallet_disp_xy_mean = _masked_mean(pallet_disp_xy, is_inserted)
        clean_insert_gate_inserted_mean = _masked_mean(clean_insert_gate, is_inserted)
        clean_align_gate_inserted_mean = _masked_mean(clean_align_gate, is_inserted)
        clean_push_gate_inserted_mean = _masked_mean(clean_push_gate, is_inserted)
        prehold_reachable_band_frac_of_inserted = _masked_mean(prehold_reachable_band.float(), is_inserted)
        prehold_reachable_band_companion_frac_of_inserted = _masked_mean(
            prehold_reachable_band_companion.float(), is_inserted
        )

        if "log" not in self.extras:
            self.extras["log"] = {}

        # Exp8.3：run 级几何常量（写入首步 summary，便于实验笔记对表）
        if not self._geom_constants_logged:
            self._geom_constants_logged = True
            _s_traj = self._exp83_traj_goal_s()
            _s_rd = self._exp83_target_center_family_s()
            _s_succ = self._exp83_success_center_s()
            print(
                f"[forklift_exp83_geom] geom/s_traj_end={_s_traj:.6f} "
                f"geom/s_rd_target={_s_rd:.6f} geom/s_success_center={_s_succ:.6f} "
                "(s: pallet-centered axis along u_in)"
            )
            self.extras["log"]["geom/s_traj_end"] = _s_traj
            self.extras["log"]["geom/s_rd_target"] = _s_rd
            self.extras["log"]["geom/s_success_center"] = _s_succ

        # 沿托盘轴签名坐标（fork_center / tip）
        s_center = torch.sum(rel_fc * u_in, dim=-1)

        # 实验 B 日志
        self.extras["log"]["paper_reward/R_plus"] = R_plus.mean()
        self.extras["log"]["paper_reward/R_minus"] = R_minus.mean()
        self.extras["log"]["paper_reward/r_d_raw"] = r_d_raw.mean()
        self.extras["log"]["paper_reward/r_d_clean_gate"] = clean_insert_gate.mean()
        self.extras["log"]["paper_reward/r_d"] = r_d.mean()
        self.extras["log"]["paper_reward/r_cd_raw"] = r_cd_raw.mean()
        self.extras["log"]["paper_reward/r_cd"] = r_cd.mean()
        self.extras["log"]["paper_reward/r_cpsi_raw"] = r_cpsi_raw.mean()
        self.extras["log"]["paper_reward/r_cpsi"] = r_cpsi.mean()
        self.extras["log"]["paper_reward/r_dirty_insert"] = r_dirty_insert.mean()
        self.extras["log"]["paper_reward/r_dirty_success"] = r_dirty_success.mean()
        self.extras["log"]["paper_reward/r_clean_insert_bonus"] = r_clean_insert_bonus.mean()
        self.extras["log"]["paper_reward/r_preinsert_align"] = r_preinsert_align.mean()
        self.extras["log"]["paper_reward/r_preinsert_retreat"] = r_preinsert_retreat.mean()
        self.extras["log"]["paper_reward/r_preinsert_push"] = r_preinsert_push.mean()
        self.extras["log"]["paper_reward/r_preinsert_push_termination"] = r_preinsert_push_termination.mean()
        self.extras["log"]["paper_reward/r_preinsert_contact_drive"] = r_preinsert_contact_drive.mean()
        self.extras["log"]["paper_reward/r_postinsert_align"] = r_postinsert_align.mean()
        self.extras["log"]["paper_reward/rg"] = rg.mean()
        self.extras["log"]["paper_reward/r_success"] = r_success.mean()
        self.extras["log"]["paper_reward/r_success_time"] = r_success_time.mean()
        self.extras["log"]["paper_reward/r_timeout"] = r_timeout.mean()
        self.extras["log"]["paper_reward/r_lift"] = r_lift.mean()
        self.extras["log"]["paper_reward/r_lift_progress"] = r_lift_progress.mean()
        self.extras["log"]["paper_reward/r_hold_counter_progress"] = r_hold_counter_progress.mean()
        self.extras["log"]["paper_reward/r_premature_lift"] = r_premature_lift.mean()
        self.extras["log"]["paper_reward/r_post_lift_stability"] = r_post_lift_stability.mean()
        self.extras["log"]["paper_reward/rp"] = rp.mean()
        self.extras["log"]["paper_reward/rv"] = rv.mean()
        self.extras["log"]["paper_reward/ra"] = ra.mean()
        self.extras["log"]["paper_reward/rini"] = rini.mean()
        self.extras["log"]["paper_reward/r_out"] = r_out.mean()

        # 核心诊断指标
        self.extras["log"]["err/dist_front_mean"] = dist_front.mean()
        self.extras["log"]["err/lateral_mean"] = y_err.mean()
        self.extras["log"]["err/root_lateral_mean"] = y_err.mean()
        self.extras["log"]["err/center_lateral_mean"] = torch.abs(
            torch.sum(rel_fc * v_lat, dim=-1)
        ).mean()
        self.extras["log"]["err/center_lateral_inserted_mean"] = inserted_center_lateral_mean
        self.extras["log"]["err/tip_lateral_mean"] = tip_y_err.mean()
        self.extras["log"]["err/tip_lateral_inserted_mean"] = inserted_tip_lateral_mean
        self.extras["log"]["err/yaw_deg_mean"] = yaw_err_deg.mean()
        self.extras["log"]["err/yaw_deg_inserted_mean"] = inserted_yaw_deg_mean

        self.extras["log"]["diag/pallet_disp_xy_mean"] = pallet_disp_xy.mean()
        self.extras["log"]["diag/pallet_disp_xy_inserted_mean"] = inserted_pallet_disp_xy_mean
        self.extras["log"]["diag/z_err_mean"] = z_err.mean()
        self.extras["log"]["diag/lift_height_mean"] = lift_height.mean()
        self.extras["log"]["diag/max_hold_counter"] = max_hold_counter
        self.extras["log"]["diag/max_hold_counter_frac"] = max_hold_counter / float(self._hold_steps)
        self.extras["log"]["diag/clean_insert_gate_inserted_mean"] = clean_insert_gate_inserted_mean
        self.extras["log"]["diag/clean_align_gate_inserted_mean"] = clean_align_gate_inserted_mean
        self.extras["log"]["diag/clean_push_gate_inserted_mean"] = clean_push_gate_inserted_mean
        self.extras["log"]["diag/prehold_reachable_strict_tip_ref_m"] = float(self.cfg.prehold_reachable_strict_tip_ref_m)
        self.extras["log"]["diag/prehold_reachable_tip_band_m"] = float(self.cfg.prehold_reachable_tip_band_m)
        self.extras["log"]["diag/prehold_reachable_tip_band_companion_m"] = float(
            self.cfg.prehold_reachable_tip_band_companion_m
        )
        self.extras["log"]["diag/training_tip_align_entry_m"] = float(training_tip_gate_m)
        self.extras["log"]["diag/strict_tip_align_entry_m"] = float(strict_tip_gate_m)
        self.extras["log"]["diag/hold_gate_curriculum_progress"] = float(curriculum_progress)
        self.extras["log"]["diag/hold_counter_delta_mean"] = hold_counter_delta.mean()
        self.extras["log"]["diag/post_lift_stability_active_frac"] = post_lift_active.mean()
        self.extras["log"]["diag/prehold_reachable_band_frac_of_inserted"] = prehold_reachable_band_frac_of_inserted
        self.extras["log"]["diag/prehold_reachable_band_companion_frac_of_inserted"] = (
            prehold_reachable_band_companion_frac_of_inserted
        )
        self.extras["log"]["diag/preinsert_active_frac"] = preinsert_active.mean()
        self.extras["log"]["diag/preinsert_contact_active_frac"] = preinsert_contact_active.mean()
        self.extras["log"]["diag/preinsert_contact_clean_gate_mean"] = preinsert_contact_clean_gate.mean()
        self.extras["log"]["diag/preinsert_push_termination_frac"] = preinsert_push_termination.float().mean()
        self.extras["log"]["diag/preinsert_y_delta_mean"] = y_delta.mean()
        self.extras["log"]["diag/preinsert_yaw_delta_mean"] = yaw_delta.mean()
        self.extras["log"]["diag/preinsert_dist_delta_mean"] = dist_delta.mean()
        self.extras["log"]["s_center_mean"] = s_center.mean()
        self.extras["log"]["s_tip_mean"] = s_tip.mean()

        self.extras["log"]["phase/frac_inserted"] = is_inserted.float().mean()
        self.extras["log"]["phase/frac_inserted_z_valid"] = is_inserted_z_valid.float().mean()
        self.extras["log"]["phase/frac_inserted_push_free"] = inserted_push_free.float().mean()
        self.extras["log"]["phase/frac_dirty_insert"] = dirty_insert.float().mean()
        self.extras["log"]["phase/frac_aligned"] = is_aligned.float().mean()
        self.extras["log"]["phase/frac_center_aligned_cfg"] = is_center_aligned_cfg.float().mean()
        self.extras["log"]["phase/frac_near_field"] = is_near_field.float().mean()
        self.extras["log"]["phase/frac_tip_aligned_near"] = is_tip_aligned_near.float().mean()
        self.extras["log"]["phase/frac_tip_constraint_ok"] = is_tip_constraint_ok.float().mean()
        self.extras["log"]["phase/frac_prehold_reachable_band"] = prehold_reachable_band.float().mean()
        self.extras["log"]["phase/frac_prehold_reachable_band_companion"] = (
            prehold_reachable_band_companion.float().mean()
        )
        self.extras["log"]["phase/frac_clean_insert_ready"] = clean_insert_ready.float().mean()
        self.extras["log"]["phase/frac_hold_entry"] = hold_state.hold_entry.float().mean()
        self.extras["log"]["phase/grace_zone_frac"] = hold_state.grace_zone.float().mean()
        self.extras["log"]["phase/frac_lifted_enough"] = lifted_enough.float().mean()
        self.extras["log"]["phase/frac_success_geom_training"] = success_geom_training.float().mean()
        self.extras["log"]["phase/frac_success_geom_strict"] = success_geom_strict.float().mean()
        self.extras["log"]["phase/frac_success_strict"] = success_strict.float().mean()
        self.extras["log"]["phase/frac_push_free"] = push_free.float().mean()
        self.extras["log"]["phase/frac_push_free_success"] = push_free_success_strict.float().mean()
        self.extras["log"]["phase/frac_rg"] = rg.mean()
        self.extras["log"]["phase/frac_success"] = success.float().mean()
        self.extras["log"]["phase/frac_training_success_raw"] = training_success_next.float().mean()
        self.extras["log"]["diag/out_of_bounds_frac"] = out_of_bounds.float().mean()
        self.extras["log"]["diag/hold_exit_exceeded_frac"] = hold_state.any_exit_exceeded.float().mean()
        self.extras["log"]["diag/success_term_frac"] = (
            success & ~tipped & ~out_of_bounds
        ).float().mean()
        
        # 轨迹指标
        self.extras["log"]["traj/d_traj_mean"] = d_traj.mean()
        self.extras["log"]["traj/yaw_traj_deg_mean"] = yaw_traj_err_deg.mean()

        self._prev_y_err[:] = y_err.detach()
        self._prev_yaw_err_deg[:] = yaw_err_deg.detach()
        self._prev_dist_front[:] = dist_front.detach()
        self._prev_lift_height[:] = lift_height.detach()

        return rew

    def _termination_masks(self) -> tuple[torch.Tensor, torch.Tensor, torch.Tensor]:
        """与 `_get_dones` 一致的 (tipped, success, out_of_bounds) 掩码，供日志复用。"""
        success = self._success_termination

        q = self.robot.data.root_quat_w
        w, x, y, z = q.unbind(-1)
        sinr_cosp = 2.0 * (w * x + y * z)
        cosr_cosp = 1.0 - 2.0 * (x * x + y * y)
        roll = torch.atan2(sinr_cosp, cosr_cosp)
        sinp = 2.0 * (w * y - z * x)
        pitch = torch.asin(torch.clamp(sinp, -1.0, 1.0))
        tipped = (torch.abs(roll) > self.cfg.max_roll_pitch_rad) | (torch.abs(pitch) > self.cfg.max_roll_pitch_rad)

        pallet_pos = self.pallet.data.root_pos_w
        fork_center = self._compute_fork_center()
        pallet_yaw = _quat_to_yaw(self.pallet.data.root_quat_w)
        dist_center_family, _ = self._exp83_target_center_family_dist(
            fork_center[:, :2], pallet_pos[:, :2], pallet_yaw
        )
        out_of_bounds = self._exp83_out_of_bounds_mask(dist_center_family)
        return tipped, success, out_of_bounds

    def _preinsert_push_termination_mask(self) -> torch.Tensor:
        """Early-stop Stage A failures that push the pallet before insertion."""
        if not self.cfg.preinsert_push_termination_enable:
            return torch.zeros((self.num_envs,), dtype=torch.bool, device=self.device)

        self._joint_pos[:] = self.robot.root_physx_view.get_dof_positions()
        pallet_pos = self.pallet.data.root_pos_w
        pallet_yaw = _quat_to_yaw(self.pallet.data.root_quat_w)
        tip = self._compute_fork_tip()

        u_in = torch.stack([torch.cos(pallet_yaw), torch.sin(pallet_yaw)], dim=-1)
        rel_tip = tip[:, :2] - pallet_pos[:, :2]
        s_tip = torch.sum(rel_tip * u_in, dim=-1)
        s_front = -0.5 * self.cfg.pallet_depth_m
        insert_depth = torch.clamp(s_tip - s_front, min=0.0)

        pallet_init_pos_xy = torch.tensor(self.cfg.pallet_cfg.init_state.pos[:2], device=self.device)
        pallet_disp_xy = torch.norm(pallet_pos[:, :2] - pallet_init_pos_xy, dim=-1)

        return (
            (pallet_disp_xy >= self.cfg.preinsert_push_termination_m)
            & (insert_depth < self._insert_thresh)
            & (self.episode_length_buf >= int(self.cfg.preinsert_push_termination_min_steps))
            & (~self._success_termination)
        )

    def _get_dones(self) -> tuple[torch.Tensor, torch.Tensor]:
        # time out
        time_out = self.episode_length_buf >= self.max_episode_length - 1

        tipped, success, out_of_bounds = self._termination_masks()
        self._preinsert_push_termination = self._preinsert_push_termination_mask()
        terminated = tipped | success | out_of_bounds | self._preinsert_push_termination
        return terminated, time_out

    # ---------------------------
    # Reset
    # ---------------------------
    def _reset_idx(self, env_ids: torch.Tensor | None):
        """按 env_ids 重置环境。

        包括：
        - 清零奖励/插入缓存
        - 托盘固定在初始位姿
        - 叉车随机化初始位姿（x/y/yaw）
        - 关节与速度归零，并刷新物理状态
        """
        if env_ids is None:
            env_ids = torch.arange(self.num_envs, device=self.device)

        # ---- 重置基类 episode 计数器（必须！否则 episode_length_buf 永不归零） ----
        # 基类 DirectRLEnv._reset_idx() 中会做 self.episode_length_buf[env_ids] = 0
        # 如果不调用 super()，RSL-RL 的 init_at_random_ep_len 随机初始值将永远不会被清除，
        # 导致环境在训练前几轮就全部进入永久超时（episode length = 1）。
        super()._reset_idx(env_ids)

        # ---- 计数器清零 ----
        self.actions[env_ids] = 0.0
        self._last_insert_depth[env_ids] = 0.0
        self._hold_counter[env_ids] = 0
        self._last_hold_entry[env_ids] = False
        self._success_termination[env_ids] = False
        self._preinsert_push_termination[env_ids] = False
        self._prev_lift_height[env_ids] = 0.0
        self._is_first_step[env_ids] = True
        self._lift_pos_target[env_ids] = 0.0
        self._milestone_flags[env_ids] = False
        self._fly_counter[env_ids] = 0
        self._stall_counter[env_ids] = 0
        self._early_stop_fly[env_ids] = False
        self._early_stop_stall[env_ids] = False
        # S1.0Q Batch-3: dead-zone stuck detector
        self._dz_stuck_counter[env_ids] = 0
        self._prev_y_err[env_ids] = 0.0
        self._prev_yaw_err_deg[env_ids] = 0.0
        self._early_stop_dz_stuck[env_ids] = False
        # S1.0Q Batch-4: penOnly 首次触发标记
        self._dz_stuck_fired[env_ids] = False
        # S1.0N: _prev_phi_align 暂时清零，在位姿写入后再初始化为当前 phi_align
        self._prev_phi_align[env_ids] = 0.0
        # S1.0O-A3: lift 进度势函数缓存清零
        self._prev_phi_lift_progress[env_ids] = 0.0
        # S1.0Q: 死区撤退 / 横向精调状态量清零
        self._prev_insert_norm[env_ids] = 0.0
        self._prev_in_dead_zone[env_ids] = False
        self._prev_phi_lat[env_ids] = 0.0
        
        # S1.0S Phase-2: 举升里程碑清零
        self._milestone_lift_10cm[env_ids] = False
        self._milestone_lift_20cm[env_ids] = False
        # S1.0T: 高举升里程碑清零
        self._milestone_lift_50cm[env_ids] = False
        self._milestone_lift_75cm[env_ids] = False
        # S1.0S Phase-R: 远场修正状态量清零
        self._prev_y_err_far[env_ids] = 0.0
        # S1.0S Phase-3: 全局停滞检测器清零
        self._global_stall_counter[env_ids] = 0
        self._prev_phi_total_stall[env_ids] = 0.0
        # S1.0Q-A2v2: 撤退窗口缓冲清零
        self._insert_norm_window[env_ids] = 0.0
        self._window_ptr[env_ids] = 0
        self._window_filled[env_ids] = False

        # ---- 托盘固定位姿（可选：后续可加随机化） ----
        pallet_pos = torch.tensor(self.cfg.pallet_cfg.init_state.pos, device=self.device).repeat(len(env_ids), 1)
        pallet_quat = torch.tensor(self.cfg.pallet_cfg.init_state.rot, device=self.device).repeat(len(env_ids), 1)
        self._write_root_pose(self.pallet, pallet_pos, pallet_quat, env_ids)

        # ---- 随机化叉车初始位姿 ----
        if self._stage_1_mode:
            x = sample_uniform(
                self.cfg.stage1_init_x_min_m,
                self.cfg.stage1_init_x_max_m,
                (len(env_ids), 1),
                device=self.device,
            )
            y = sample_uniform(
                self.cfg.stage1_init_y_min_m,
                self.cfg.stage1_init_y_max_m,
                (len(env_ids), 1),
                device=self.device,
            )
            yaw = sample_uniform(
                self.cfg.stage1_init_yaw_deg_min * math.pi / 180.0,
                self.cfg.stage1_init_yaw_deg_max * math.pi / 180.0,
                (len(env_ids), 1),
                device=self.device,
            )
        else:
            # 实验 B: 保守随机初始分布 (1.5~2.5m 距离，±0.5m 横向，±15° 偏航)
            # 托盘前沿在 -1.08m，叉尖在车体前方 1.87m
            # 距离托盘前沿 d_m 时，车体 x = -1.08 - 1.87 - d = -2.95 - d
            # d_m = 1.5m -> x = -4.45m
            # d_m = 2.5m -> x = -5.45m
            x = sample_uniform(-5.45, -4.45, (len(env_ids), 1), device=self.device)
            y = sample_uniform(-0.5, 0.5, (len(env_ids), 1), device=self.device)
            yaw = sample_uniform(
                -15.0 * math.pi / 180.0,
                15.0 * math.pi / 180.0,
                (len(env_ids), 1),
                device=self.device,
            )
        z = torch.full((len(env_ids), 1), 0.03, device=self.device)

        pos = torch.cat([x, y, z], dim=1)
        half = yaw * 0.5
        quat = torch.cat([torch.cos(half), torch.zeros_like(half), torch.zeros_like(half), torch.sin(half)], dim=1)

        self._write_root_pose(self.robot, pos, quat, env_ids)

        # 速度清零
        zeros3 = torch.zeros((len(env_ids), 3), device=self.device)
        self._write_root_vel(self.robot, zeros3, zeros3, env_ids)

        # 关节归零（lift down, wheels zero, steering zero）
        joint_pos = self.robot.data.default_joint_pos[env_ids].clone()
        joint_vel = torch.zeros_like(joint_pos)
        self._write_joint_state(self.robot, joint_pos, joint_vel, env_ids)

        # Exp8.3 B0′：在写入 pallet / robot / joint 之后，用 reset 张量生成参考轨迹，
        # 避免旧 episode 位姿污染 r_cd / r_cpsi。
        self._prev_phi_traj[env_ids] = 0.0
        if bool(getattr(self.cfg, "use_reference_trajectory", True)):
            lift_j = joint_pos[:, self._lift_id]
            fc3 = self._compute_fork_center_from_root_lift(pos, quat, lift_j)
            p_yaw = _quat_to_yaw(pallet_quat)
            r_yaw = _quat_to_yaw(quat)
            self._build_reference_trajectory(
                env_ids,
                fork_center_xy=fc3[:, :2],
                robot_yaw=r_yaw,
                pallet_pos_xy=pallet_pos[:, :2],
                pallet_yaw=p_yaw,
            )
            self._run_runtime_u0_check(
                env_ids,
                fork_center_xy=fc3[:, :2],
                robot_yaw=r_yaw,
                pallet_pos_xy=pallet_pos[:, :2],
                pallet_yaw=p_yaw,
            )
            self._run_runtime_u1_target_center_family_check(
                env_ids,
                pallet_pos_xy=pallet_pos[:, :2],
                pallet_yaw=p_yaw,
            )

        # ---- 基线 fork tip 高度 ----
        # S1.0h 修复：不再调用 scene.write_data_to_sim() / sim.reset() / scene.update()
        # sim.reset() 是全局 PhysX 引擎重置，会将所有 1024 个环境的位姿覆盖回 config 默认值，
        # 完全摧毁上面刚写入的随机化位姿（详见 S0.7 postmortem）。
        # _fork_z_base = 0.0（训练日志实测），因此 fork_tip_z0 = root_z = z.squeeze(-1)，误差为零。
        self._fork_tip_z0[env_ids] = z.squeeze(-1)

        # ---- S1.0k: 初始化势函数缓存 ----
        # reset 时 insert_depth ≈ 0、lift_height ≈ 0
        # 精确计算 phi_total 初始值，避免首步异常大的 r_pot
        # 注：_is_first_step 保护会清零首步 r_pot，但精确初始化更安全
        y_err_reset = torch.abs(y.squeeze(-1))
        yaw_err_deg_reset = torch.abs(yaw.squeeze(-1)) * (180.0 / math.pi)
        # S1.0L: reset 初始化与 _get_rewards 保持一致（stage_distance_ref=base）。
        cp_reset = torch.cos(torch.zeros_like(x.squeeze(-1)))
        sp_reset = torch.sin(torch.zeros_like(x.squeeze(-1)))
        u_in_reset = torch.stack([cp_reset, sp_reset], dim=-1)
        pallet_pos_reset = pallet_pos[:, :2]
        rel_base_reset = pos[:, :2] - pallet_pos_reset
        s_base_reset = torch.sum(rel_base_reset * u_in_reset, dim=-1)
        s_front_reset = -0.5 * self.cfg.pallet_depth_m
        
        # 始终计算真实的叉尖距离，用于实验 3.2 的 commit 奖励
        cos_yaw_reset = torch.cos(yaw.squeeze(-1))
        sin_yaw_reset = torch.sin(yaw.squeeze(-1))
        tip_x_reset = pos[:, 0] + self._fork_forward_offset * cos_yaw_reset
        tip_y_reset = pos[:, 1] + self._fork_forward_offset * sin_yaw_reset
        rel_tip_reset = torch.stack([tip_x_reset, tip_y_reset], dim=-1) - pallet_pos_reset
        s_tip_reset = torch.sum(rel_tip_reset * u_in_reset, dim=-1)
        true_dist_front_reset = torch.clamp(s_front_reset - s_tip_reset, min=0.0)
        
        if self.cfg.stage_distance_ref == "base":
            dist_front_reset = torch.clamp(s_front_reset - s_base_reset, min=0.0)
        else:
            dist_front_reset = true_dist_front_reset

        # 实验 3.2: 近场 commit 状态量初始化 (使用真实的叉尖距离)
        self._prev_dist_front[env_ids] = true_dist_front_reset.detach()
        self._prev_y_err[env_ids] = y_err_reset.detach()
        self._prev_yaw_err_deg[env_ids] = yaw_err_deg_reset.detach()

        # 计算 phi1 初始值
        e_band_reset = torch.where(
            dist_front_reset < self.cfg.d1_min, self.cfg.d1_min - dist_front_reset,
            torch.where(dist_front_reset > self.cfg.d1_max, dist_front_reset - self.cfg.d1_max,
                        torch.zeros_like(dist_front_reset))
        )
        E1_reset = (e_band_reset / self.cfg.e_band_scale
                     + y_err_reset / self.cfg.y_scale1
                     + yaw_err_deg_reset / self.cfg.yaw_scale1)
        phi1_reset = self.cfg.k_phi1 / (1.0 + E1_reset)

        # 计算 phi2 初始值
        E2_reset = (dist_front_reset / self.cfg.d2_scale
                     + y_err_reset / self.cfg.y_scale2
                     + yaw_err_deg_reset / self.cfg.yaw_scale2)
        phi2_base_reset = self.cfg.k_phi2 / (1.0 + E2_reset)
        w_band_reset = smoothstep(
            (self.cfg.d1_max - dist_front_reset) / (self.cfg.d1_max - self.cfg.d1_min)
        )
        w_align2_reset = torch.exp(
            -(y_err_reset / self.cfg.y_gate2) ** 2
            - (yaw_err_deg_reset / self.cfg.yaw_gate2) ** 2
        )
        phi2_reset = phi2_base_reset * w_band_reset * w_align2_reset

        # reset 时 insert_norm ≈ 0, lift_height ≈ 0 → phi_ins = 0, phi_lift = 0
        if self.cfg.suppress_preinsert_phi_with_w3:
            phi_total_reset = phi1_reset + phi2_reset  # w3≈0 时等价
        else:
            phi_total_reset = phi1_reset + phi2_reset
        self._last_phi_total[env_ids] = phi_total_reset

        # 举升增量缓存
        self._last_lift_pos[env_ids] = 0.0

        # S1.0N: 初始化 _prev_phi_align 为当前位姿的 phi_align，防"开局白嫖"
        # 注意：此时 robot 位姿已写入但 PhysX 尚未 step，
        # 使用 reset 时已知的 y_err/yaw_err 直接计算（避免依赖 PhysX view）
        phi_align_init = (
            torch.exp(-(y_err_reset / self.cfg.hold_align_sigma_y) ** 2)
            * torch.exp(-(yaw_err_deg_reset / self.cfg.hold_align_sigma_yaw) ** 2)
        )
        self._prev_phi_align[env_ids] = phi_align_init.detach()

        # S1.0Q: 初始化 _prev_phi_lat 为 reset 位姿的 phi_lat（防"开局白嫖"）
        phi_lat_init = torch.exp(-(y_err_reset / self.cfg.lat_fine_sigma) ** 2)
        self._prev_phi_lat[env_ids] = phi_lat_init.detach()
        # _prev_insert_norm 在 reset 时 insert_norm ≈ 0，保持清零即可

        # 注：不再额外调用 self.robot.reset(env_ids)，
        # super()._reset_idx() 已通过 scene.reset(env_ids) 调用过一次。

    # ---------------------------
    # Compatibility helpers (API name differences across versions)
    # ---------------------------
    def _write_root_pose(self, asset, pos, quat, env_ids):
        """设置 asset 的根位姿。

        Isaac Lab >=1.x API: write_root_pose_to_sim(root_pose: (N,7), env_ids)
        root_pose = [pos(3), quat(4)]  (quat 格式 w,x,y,z)
        """
        root_pose = torch.cat([pos, quat], dim=-1)  # (N, 7)
        if hasattr(asset, "write_root_pose_to_sim"):
            asset.write_root_pose_to_sim(root_pose, env_ids)
        elif hasattr(asset, "write_root_state_to_sim"):
            root_state = torch.zeros((len(env_ids), 13), device=self.device)
            root_state[:, 0:7] = root_pose
            asset.write_root_state_to_sim(root_state, env_ids)
        else:
            raise AttributeError("Asset has no known root pose writer.")

    def _write_root_vel(self, asset, lin_vel, ang_vel, env_ids):
        """设置 asset 的根速度。

        Isaac Lab >=1.x API: write_root_velocity_to_sim(root_velocity: (N,6), env_ids)
        root_velocity = [lin_vel(3), ang_vel(3)]
        """
        root_vel = torch.cat([lin_vel, ang_vel], dim=-1)  # (N, 6)
        if hasattr(asset, "write_root_velocity_to_sim"):
            asset.write_root_velocity_to_sim(root_vel, env_ids)
        elif hasattr(asset, "write_root_state_to_sim"):
            pass
        else:
            raise AttributeError("Asset has no known root velocity writer.")

    def _write_joint_state(self, articulation, joint_pos, joint_vel, env_ids):
        """设置关节状态（位置 + 速度）。

        注意 write_joint_state_to_sim 的第三个位置参数是 joint_ids，
        必须用关键字参数传 env_ids，否则会被误当作 joint_ids。
        """
        if hasattr(articulation, "write_joint_state_to_sim"):
            articulation.write_joint_state_to_sim(joint_pos, joint_vel, env_ids=env_ids)
        elif hasattr(articulation, "write_joint_pos_to_sim") and hasattr(articulation, "write_joint_vel_to_sim"):
            articulation.write_joint_pos_to_sim(joint_pos, env_ids=env_ids)
            articulation.write_joint_vel_to_sim(joint_vel, env_ids=env_ids)
        else:
            raise AttributeError("Articulation has no known joint state writer.")
