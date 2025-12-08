# Copyright 2025 ROBOTIS CO., LTD.
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.
#
# Author: Taehyeong Kim

# Copyright (c) 2022-2025, The Isaac Lab Project Developers.
# All rights reserved.
#
# SPDX-License-Identifier: BSD-3-Clause

from __future__ import annotations

import math
import random
import torch
from typing import TYPE_CHECKING

import isaaclab.utils.math as math_utils
from isaaclab.assets import Articulation, AssetBase
from isaaclab.sensors.camera import Camera
from isaaclab.managers import SceneEntityCfg
from typing import Literal

from pxr import Gf

if TYPE_CHECKING:
    from isaaclab.envs import ManagerBasedEnv


def create_joint_position_mapping(joint_names: list[str], desired_values: dict[str, float]) -> torch.Tensor:
    """Create a tensor with joint positions in the correct order based on joint names."""
    joint_positions = []
    
    for joint_name in joint_names:
        if joint_name in desired_values:
            joint_positions.append(desired_values[joint_name])
        else:
            joint_positions.append(0.0)  # Default value
    
    return torch.tensor(joint_positions, dtype=torch.float32)

def set_default_joint_pose(
    env: ManagerBasedEnv,
    env_ids: torch.Tensor,
    joint_positions: dict[str, float],  # Change to dict instead of list
    asset_cfg: SceneEntityCfg = SceneEntityCfg("robot"),
):
    """Set the default joint positions for the robot using joint names."""
    asset: Articulation = env.scene[asset_cfg.name]
    
    # Create properly ordered tensor from joint name mapping
    default_pose_tensor = create_joint_position_mapping(asset.joint_names, joint_positions)
    default_pose_tensor = default_pose_tensor.to(device=env.device)
    
    # Ensure correct shape for multiple environments
    if default_pose_tensor.dim() == 1:
        default_pose_tensor = default_pose_tensor.unsqueeze(0).repeat(len(env_ids), 1)
    
    # Set joint positions
    asset.set_joint_position_target(default_pose_tensor, env_ids=env_ids)
    asset.write_joint_state_to_sim(default_pose_tensor, torch.zeros_like(default_pose_tensor), env_ids=env_ids)

def randomize_joint_by_gaussian_offset(
    env: ManagerBasedEnv,
    env_ids: torch.Tensor,
    mean: float,
    std: float,
    asset_cfg: SceneEntityCfg = SceneEntityCfg("robot"),
    joint_names: list[str] = None,  # Add parameter to specify which joints to randomize
):
    asset: Articulation = env.scene[asset_cfg.name]

    # Use current joint positions instead of default positions
    joint_pos = asset.data.joint_pos[env_ids].clone()
    joint_vel = asset.data.joint_vel[env_ids].clone()
    
    # If joint_names is specified, only randomize those joints
    if joint_names is not None:
        for joint_name in joint_names:
            if joint_name in asset.joint_names:
                joint_idx = asset.joint_names.index(joint_name)
                noise = math_utils.sample_gaussian(mean, std, (len(env_ids), 1), joint_pos.device)
                joint_pos[:, joint_idx:joint_idx+1] += noise
    else:
        # Original behavior - randomize all joints
        joint_pos += math_utils.sample_gaussian(mean, std, joint_pos.shape, joint_pos.device)

    # Clamp joint pos to limits
    joint_pos_limits = asset.data.soft_joint_pos_limits[env_ids]
    joint_pos = joint_pos.clamp_(joint_pos_limits[..., 0], joint_pos_limits[..., 1])

    # Set into the physics simulation
    asset.set_joint_position_target(joint_pos, env_ids=env_ids)
    asset.set_joint_velocity_target(joint_vel, env_ids=env_ids)
    asset.write_joint_state_to_sim(joint_pos, joint_vel, env_ids=env_ids)


def sample_object_poses(
    num_objects: int,
    min_separation: float = 0.0,
    pose_range: dict[str, tuple[float, float]] = {},
    max_sample_tries: int = 5000,
):
    range_list = [pose_range.get(key, (0.0, 0.0)) for key in ["x", "y", "z", "roll", "pitch", "yaw"]]
    pose_list = []

    for i in range(num_objects):
        for j in range(max_sample_tries):
            sample = [random.uniform(range[0], range[1]) for range in range_list]

            # Accept pose if it is the first one, or if reached max num tries
            if len(pose_list) == 0 or j == max_sample_tries - 1:
                pose_list.append(sample)
                break

            # Check if pose of object is sufficiently far away from all other objects
            separation_check = [math.dist(sample[:3], pose[:3]) > min_separation for pose in pose_list]
            if False not in separation_check:
                pose_list.append(sample)
                break

    return pose_list


def randomize_object_pose(
    env: ManagerBasedEnv,
    env_ids: torch.Tensor,
    asset_cfgs: list[SceneEntityCfg],
    min_separation: float = 0.0,
    pose_range: dict[str, tuple[float, float]] = {},
    max_sample_tries: int = 5000,
):
    if env_ids is None:
        return

    # Randomize poses in each environment independently
    for cur_env in env_ids.tolist():
        pose_list = sample_object_poses(
            num_objects=len(asset_cfgs),
            min_separation=min_separation,
            pose_range=pose_range,
            max_sample_tries=max_sample_tries,
        )

        # Randomize pose for each object
        for i in range(len(asset_cfgs)):
            asset_cfg = asset_cfgs[i]
            asset = env.scene[asset_cfg.name]

            # Write pose to simulation
            pose_tensor = torch.tensor([pose_list[i]], device=env.device)
            positions = pose_tensor[:, 0:3] + env.scene.env_origins[cur_env, 0:3]
            orientations = math_utils.quat_from_euler_xyz(pose_tensor[:, 3], pose_tensor[:, 4], pose_tensor[:, 5])
            asset.write_root_pose_to_sim(
                torch.cat([positions, orientations], dim=-1), env_ids=torch.tensor([cur_env], device=env.device)
            )
            asset.write_root_velocity_to_sim(
                torch.zeros(1, 6, device=env.device), env_ids=torch.tensor([cur_env], device=env.device)
            )


def randomize_scene_lighting_domelight(
    env: ManagerBasedEnv,
    env_ids: torch.Tensor,
    intensity_range: tuple[float, float] = (1000.0, 3000.0),
    color_range: tuple[tuple[float, float], tuple[float, float], tuple[float, float]] = ((0.5, 1.0), (0.5, 1.0), (0.5, 1.0)),
    asset_cfg: SceneEntityCfg = SceneEntityCfg("light"),
):
    asset: AssetBase = env.scene[asset_cfg.name]
    light_prim = asset.prims[0]

    # Random intensity
    new_intensity = random.uniform(intensity_range[0], intensity_range[1])
    intensity_attr = light_prim.GetAttribute("inputs:intensity")
    intensity_attr.Set(new_intensity)

    # Random color
    new_color = Gf.Vec3f(
        random.uniform(color_range[0][0], color_range[0][1]),
        random.uniform(color_range[1][0], color_range[1][1]),
        random.uniform(color_range[2][0], color_range[2][1]),
    )
    color_attr = light_prim.GetAttribute("inputs:color")
    color_attr.Set(new_color)


def randomize_camera_pose(
    env: ManagerBasedEnv,
    env_ids: torch.Tensor,
    asset_cfg: SceneEntityCfg,
    pose_range: dict[str, tuple[float, float]] = None,
    convention: Literal["opengl", "ros", "world"] = "ros",
):
    """Reset the camera to a random position and rotation within the given ranges."""
    if pose_range is None:
        pose_range = {
            "x": (-0.02, 0.02),
            "y": (-0.02, 0.02),
            "z": (-0.02, 0.02),
            "roll": (-0.1, 0.1),
            "pitch": (-0.1, 0.1),
            "yaw": (-0.1, 0.1),
        }

    asset: Camera = env.scene[asset_cfg.name]

    # Store initial positions and quaternions once
    if not hasattr(asset, "_initial_pos_w"):
        asset._initial_pos_w = asset.data.pos_w.clone()
        asset._initial_quat_w_ros = asset.data.quat_w_ros.clone()
        asset._initial_quat_w_opengl = asset.data.quat_w_opengl.clone()
        asset._initial_quat_w_world = asset.data.quat_w_world.clone()

    ori_pos_w = asset._initial_pos_w
    if convention == "ros":
        ori_quat_w = asset._initial_quat_w_ros
    elif convention == "opengl":
        ori_quat_w = asset._initial_quat_w_opengl
    elif convention == "world":
        ori_quat_w = asset._initial_quat_w_world

    # Get pose ranges
    range_list = [pose_range.get(k, (0.0, 0.0)) for k in ["x", "y", "z", "roll", "pitch", "yaw"]]
    ranges = torch.tensor(range_list, device=asset.device)

    # Sample random offsets for each environment independently
    rand_samples = math_utils.sample_uniform(
        ranges[:, 0], ranges[:, 1], (len(env_ids), 6), device=asset.device
    )

    # Apply per-env randomization
    for i, env_id in enumerate(env_ids.tolist()):
        pos = ori_pos_w[env_id, 0:3] + rand_samples[i, 0:3]
        ori_delta = math_utils.quat_from_euler_xyz(
            rand_samples[i, 3], rand_samples[i, 4], rand_samples[i, 5]
        )
        ori = math_utils.quat_mul(ori_quat_w[env_id], ori_delta)
        asset.set_world_poses(
            pos.unsqueeze(0), ori.unsqueeze(0), env_ids=torch.tensor([env_id], device=asset.device), convention=convention
        )

def randomize_robot_base_pose(
    env: ManagerBasedEnv,
    env_ids: torch.Tensor,
    asset_cfg: SceneEntityCfg = SceneEntityCfg("robot"),
    pose_range: dict[str, tuple[float, float]] = None,
):
    """Randomize the robot's base position and orientation."""
    if pose_range is None:
        return

    if env_ids is None:
        return

    asset: Articulation = env.scene[asset_cfg.name]

    # Randomize poses in each environment independently
    for cur_env in env_ids.tolist():
        # Sample random pose
        range_list = [pose_range.get(key, (0.0, 0.0)) for key in ["x", "y", "z", "roll", "pitch", "yaw"]]
        sample = [random.uniform(range[0], range[1]) for range in range_list]

        # Convert to tensor and add environment origin
        pose_tensor = torch.tensor([sample], device=env.device)
        position = pose_tensor[:, 0:3] + env.scene.env_origins[cur_env, 0:3]
        orientation = math_utils.quat_from_euler_xyz(pose_tensor[:, 3], pose_tensor[:, 4], pose_tensor[:, 5])

        # Write pose to simulation
        asset.write_root_pose_to_sim(
            torch.cat([position, orientation], dim=-1), 
            env_ids=torch.tensor([cur_env], device=env.device)
        )
        asset.write_root_velocity_to_sim(
            torch.zeros(1, 6, device=env.device), 
            env_ids=torch.tensor([cur_env], device=env.device)
        )

def set_object_pose(
    env: ManagerBasedEnv,
    env_ids: torch.Tensor,
    asset_cfg: SceneEntityCfg,
    pose: dict[str, float],
):
    """Set a fixed pose for an object."""
    if env_ids is None:
        return

    asset = env.scene[asset_cfg.name]

    # Extract pose values with defaults
    x = pose.get("x", 0.0)
    y = pose.get("y", 0.0)
    z = pose.get("z", 0.0)
    roll = pose.get("roll", 0.0)
    pitch = pose.get("pitch", 0.0)
    yaw = pose.get("yaw", 0.0)

    # Set poses for each environment
    for cur_env in env_ids.tolist():
        # Convert to tensor and add environment origin
        position = torch.tensor([[x, y, z]], device=env.device) + env.scene.env_origins[cur_env, 0:3]
        orientation = math_utils.quat_from_euler_xyz(
            torch.tensor([roll], device=env.device),
            torch.tensor([pitch], device=env.device),
            torch.tensor([yaw], device=env.device)
        )

        # Write pose to simulation
        asset.write_root_pose_to_sim(
            torch.cat([position, orientation], dim=-1),
            env_ids=torch.tensor([cur_env], device=env.device)
        )
        asset.write_root_velocity_to_sim(
            torch.zeros(1, 6, device=env.device),
            env_ids=torch.tensor([cur_env], device=env.device)
        )


# Pre-defined slot positions for object placement
# Left side slots (y > 0)
LEFT_SLOTS = [
    (0.555, 0.26, 0.95),
    (0.555, 0.087, 0.95),
    (0.555, 0.26, 1.235),
    (0.555, 0.087, 1.235),
]

# Right side slots (y < 0)
RIGHT_SLOTS = [
    (0.555, -0.087, 0.95),
    (0.555, -0.26, 0.95),
    (0.555, -0.087, 1.235),
    (0.555, -0.26, 1.235),
]

ALL_SLOTS = LEFT_SLOTS + RIGHT_SLOTS


def randomize_objects_on_slots(
    env: ManagerBasedEnv,
    env_ids: torch.Tensor,
    target_asset_cfg: SceneEntityCfg,
    other_asset_cfgs: list[SceneEntityCfg],
    target_side: Literal["left", "right"] = "left",
):
    """
    Randomize object positions using predefined slot positions.
    
    Args:
        env: The environment instance
        env_ids: Environment indices to reset
        target_asset_cfg: The target object that should be placed on a specific side
        other_asset_cfgs: Other objects that can be placed anywhere (remaining slots)
        target_side: Which side ("left" or "right") to place the target object
    """
    if env_ids is None:
        return

    # Determine which slots to use for target
    if target_side == "left":
        target_slots = LEFT_SLOTS.copy()
    else:
        target_slots = RIGHT_SLOTS.copy()

    # Randomize poses in each environment independently
    for cur_env in env_ids.tolist():
        # Make copies of slot lists to track available slots
        available_target_slots = target_slots.copy()
        available_all_slots = ALL_SLOTS.copy()

        # 1. Place target object on its designated side
        target_asset = env.scene[target_asset_cfg.name]
        target_slot = random.choice(available_target_slots)
        available_all_slots.remove(target_slot)  # Remove from all slots

        # Write target pose
        position = torch.tensor([[target_slot[0], target_slot[1], target_slot[2]]], device=env.device)
        position = position + env.scene.env_origins[cur_env, 0:3]
        orientation = math_utils.quat_from_euler_xyz(
            torch.tensor([0.0], device=env.device),
            torch.tensor([0.0], device=env.device),
            torch.tensor([0.0], device=env.device)
        )
        target_asset.write_root_pose_to_sim(
            torch.cat([position, orientation], dim=-1),
            env_ids=torch.tensor([cur_env], device=env.device)
        )
        target_asset.write_root_velocity_to_sim(
            torch.zeros(1, 6, device=env.device),
            env_ids=torch.tensor([cur_env], device=env.device)
        )

        # 2. Place other objects on remaining slots
        random.shuffle(available_all_slots)
        for i, asset_cfg in enumerate(other_asset_cfgs):
            if i >= len(available_all_slots):
                break  # No more slots available
            
            asset = env.scene[asset_cfg.name]
            slot = available_all_slots[i]

            # Write pose
            position = torch.tensor([[slot[0], slot[1], slot[2]]], device=env.device)
            position = position + env.scene.env_origins[cur_env, 0:3]
            orientation = math_utils.quat_from_euler_xyz(
                torch.tensor([0.0], device=env.device),
                torch.tensor([0.0], device=env.device),
                torch.tensor([0.0], device=env.device)
            )
            asset.write_root_pose_to_sim(
                torch.cat([position, orientation], dim=-1),
                env_ids=torch.tensor([cur_env], device=env.device)
            )
            asset.write_root_velocity_to_sim(
                torch.zeros(1, 6, device=env.device),
                env_ids=torch.tensor([cur_env], device=env.device)
            )
