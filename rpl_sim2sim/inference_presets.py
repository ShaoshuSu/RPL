"""``holosoma_inference`` presets for the RPL / FALCON-Terrains depth student.

``inference:g1-29dof-rpl-depth`` pairs with ``python -m rpl_sim2sim.run_sim`` (FALCON's sim2sim
environment). Robot gains, stand pose, action scale and observation layout follow FALCON's
``loco_manip_cam`` / ``g1_29dof_depth`` sim2sim configs, which are also what the distillation
preset trains against.
"""

from __future__ import annotations

from dataclasses import replace
from pathlib import Path

from holosoma_inference.config.config_types.camera import CameraConfig, CameraPose, CameraProps
from holosoma_inference.config.config_types.inference import InferenceConfig
from holosoma_inference.config.config_values.camera import CAMERA_REGISTRY
from holosoma_inference.config.config_values.inference import INFERENCE_REGISTRY
from holosoma_inference.config.config_values.observation import OBSERVATION_REGISTRY
from holosoma_inference.config.config_values.robot import ROBOT_REGISTRY, g1_29dof
from holosoma_inference.config.config_values.task import TASK_REGISTRY, locomotion
from holosoma_inference.policies.dual_mode import _BUILTIN_POLICY_TYPES

from rpl_sim2sim.policy import RplObservationConfig

MODELS_DIR = Path(__file__).resolve().parent / "models"
# DEFAULT_MODEL = MODELS_DIR / "rpl_original_model_19999.onnx"
DEFAULT_MODEL = MODELS_DIR / "rpl_holosoma_model_19999.onnx"

# FALCON ``g1_29dof.yaml``: PD gains, stand pose (legs bent, arms at zero), motor order.
# fmt: off
_KP = (100, 100, 100, 150, 40, 40) * 2 + (200, 40, 40) + (40,) * 14
_KD = (2.0, 2.0, 2.0, 4.0, 2.0, 2.0) * 2 + (5.0, 5.0, 5.0) + (1.0,) * 14
_STAND = (-0.1, 0.0, 0.0, 0.3, -0.2, 0.0) * 2 + (0.0,) * 17
# fmt: on

g1_29dof_rpl = replace(
    g1_29dof,
    default_dof_angles=_STAND,
    default_motor_angles=_STAND,
    motor_kp=tuple(float(k) for k in _KP),
    motor_kd=_KD,
)

# 115-dim frame x 5 (actor), 2 x 27 x 48 depth x 2 frames pushed at 10 Hz, command velocity.
rpl_depth_observation = RplObservationConfig(
    obs_dict={
        "actor_obs": [
            "actions",
            "base_ang_vel",
            "command_ang_vel",
            "command_base_height",
            "command_lin_vel",
            "command_stand",
            "command_waist_dofs",
            "dof_pos",
            "dof_vel",
            "projected_gravity",
            "ref_upper_dof_pos",
        ],
        "perception_obs": ["cam_depth"],
        "command_lin_vel_obs": ["command_lin_vel"],
    },
    obs_dims={
        "actions": 29,
        "base_ang_vel": 3,
        "command_ang_vel": 1,
        "command_base_height": 1,
        "command_lin_vel": 2,
        "command_stand": 1,
        "command_waist_dofs": 3,
        "dof_pos": 29,
        "dof_vel": 29,
        "projected_gravity": 3,
        "ref_upper_dof_pos": 14,
        "cam_depth": 2 * 27 * 48,
    },
    obs_scales={
        "actions": 1.0,
        "base_ang_vel": 0.25,
        "command_ang_vel": 1.0,
        "command_base_height": 2.0,
        "command_lin_vel": 1.0,
        "command_stand": 1.0,
        "command_waist_dofs": 1.0,
        "dof_pos": 1.0,
        "dof_vel": 0.05,
        "projected_gravity": 1.0,
        "ref_upper_dof_pos": 1.0,
        "cam_depth": 1.0,
    },
    history_length_dict={"actor_obs": 5, "perception_obs": 2, "command_lin_vel_obs": 1},
    obs_intervals={"actor_obs": 1, "perception_obs": 5, "command_lin_vel_obs": 1},
)

rpl_depth_task = replace(
    locomotion,
    model_path=str(DEFAULT_MODEL),
    policy_type="rpl_depth",
    rl_rate=50,
    policy_action_scale=0.25,
    use_phase=False,
    desired_base_height=0.75,
    residual_upper_body_action=False,
    interface="lo",
    # FALCON's ``task.USE_JOYSTICK=true``: the Xbox pad the sim publishes as the wireless controller.
    # ``--task.velocity-input keyboard --task.state-input keyboard`` drives it from the terminal.
    velocity_input="interface",
    state_input="interface",
)

# Front then back, as published by the sim's ``depth-shm-falcon`` plugin. Only the camera count and
# resized size are read by the policy; poses/props document the rig (FALCON sim2sim cameras).
rpl_dual_depth = CameraConfig(
    poses={
        "cam_front_depth": CameraPose(
            parent_link="torso_link", camera_offset=(0.15, 0.06, 0.02), camera_rotation=(0.0, 75.0, 0.0)
        ),
        "cam_back_depth": CameraPose(
            parent_link="torso_link", camera_offset=(-0.13, -0.06, 0.02), camera_rotation=(0.0, 75.0, 180.0)
        ),
    },
    props=CameraProps(
        image_type="depth",
        width=240,
        height=135,
        resized_width=48,
        resized_height=27,
        horizontal_fov=101.41,
        vertical_fov=69.0,
        near_clip=0.1,
        far_clip=2.0,
        frame_rate=10,
    ),
)

g1_29dof_rpl_depth = InferenceConfig(
    robot=g1_29dof_rpl,
    observation=rpl_depth_observation,
    task=rpl_depth_task,
    camera=rpl_dual_depth,
)


# Terrain teachers (tools/export_teacher_onnx.py): same actor_obs, the 16 x 10 height map from
# run_sim.py --height-scan as perception_obs (history 1, every step, as in the teachers' training config).
DEFAULT_TEACHER_MODEL = MODELS_DIR / "rpl_teacher_stairs_up_model_74998.onnx"
rpl_teacher_observation = RplObservationConfig(
    obs_dict={"actor_obs": rpl_depth_observation.obs_dict["actor_obs"], "perception_obs": ["height_scan"]},
    obs_dims={**{k: v for k, v in rpl_depth_observation.obs_dims.items() if k != "cam_depth"}, "height_scan": 160},
    obs_scales={**{k: v for k, v in rpl_depth_observation.obs_scales.items() if k != "cam_depth"}, "height_scan": 1.0},
    history_length_dict={"actor_obs": 5, "perception_obs": 1},
    obs_intervals={"actor_obs": 1, "perception_obs": 1},
)
rpl_teacher_task = replace(rpl_depth_task, model_path=str(DEFAULT_TEACHER_MODEL), policy_type="rpl_heightmap_teacher")
g1_29dof_rpl_teacher = InferenceConfig(
    robot=g1_29dof_rpl,
    observation=rpl_teacher_observation,
    task=rpl_teacher_task,
)


def register() -> None:
    """Add the presets to ``holosoma_inference``'s registries (idempotent)."""
    ROBOT_REGISTRY.add("g1-29dof-rpl", g1_29dof_rpl)
    OBSERVATION_REGISTRY.add("rpl-depth", rpl_depth_observation)
    TASK_REGISTRY.add("rpl-depth", rpl_depth_task)
    CAMERA_REGISTRY.add("rpl-dual-depth", rpl_dual_depth)
    INFERENCE_REGISTRY.add("g1-29dof-rpl-depth", g1_29dof_rpl_depth)
    OBSERVATION_REGISTRY.add("rpl-teacher", rpl_teacher_observation)
    TASK_REGISTRY.add("rpl-teacher", rpl_teacher_task)
    INFERENCE_REGISTRY.add("g1-29dof-rpl-teacher", g1_29dof_rpl_teacher)
    # Also resolvable without reinstalling (pyproject entry point): holosoma's built-in fallback table.
    _BUILTIN_POLICY_TYPES["rpl_heightmap_teacher"] = ("rpl_sim2sim.teacher_policy", "RplHeightmapTeacherPolicy")


register()

__all__ = [
    "DEFAULT_MODEL",
    "DEFAULT_TEACHER_MODEL",
    "g1_29dof_rpl",
    "g1_29dof_rpl_depth",
    "g1_29dof_rpl_teacher",
    "rpl_depth_observation",
    "rpl_depth_task",
    "rpl_teacher_observation",
    "rpl_teacher_task",
]
