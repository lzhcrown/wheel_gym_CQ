"""Local-patch measurement timing, real wheel projections, and reset isolation."""
import json
import math
from types import SimpleNamespace as NS
import unittest
from unittest.mock import Mock, patch

import numpy as np
import isaacgym
import torch

from wheel_legged_gym.envs.nezha2.nezha2_env import Nezha2FreeEnv
from wheel_legged_gym.evaluation.crossing import WheelWindowCrossing
from wheel_legged_gym.evaluation.geometry import wheel_geometry_from_cfg
from wheel_legged_gym.evaluation.patch_env import PatchEvaluationEnv, project_wheel_cylinders
from wheel_legged_gym.evaluation.patch_terrain import PatchEvaluationTerrain
from tests.test_evaluation_env import bare_env, offline_energy


def geometry_cfg():
    angles = {"%s_%s_joint" % (leg, joint): value
              for leg in ("FL", "FR", "RL", "RR")
              for joint, value in (("hip", -.1 if leg.endswith("L") else .1),
                                   ("thigh", .925), ("calf", -1.85), ("foot", 0.))}
    return NS(asset=NS(file="{WHEEL_LEGGED_GYM_ROOT_DIR}/resources/robots/urdf2.1/urdf/nezha3_description.urdf"),
              init_state=NS(default_joint_angles=angles))


def patch_env(sign=1, quota=1, all_wheels=False):
    base = bare_env(1, quota)
    env = PatchEvaluationEnv.__new__(PatchEvaluationEnv)
    env.__dict__.update(base.__dict__)
    env.metrics.active[:] = False
    env.metrics.episode_index[:] = -1
    env.attempt_indices[:] = -1
    env._attempt_metadata = [{}]
    env.crossing = WheelWindowCrossing(1, "cpu")
    env.attempt_active = torch.zeros(1, dtype=torch.bool)
    env.evaluation.command_vx = float(sign)
    env.evaluation.wheel_side = "all" if all_wheels else "both"
    env.root_states[:, 0] = -.8 if sign > 0 else (7. if all_wheels else 1.2)
    env.root_states[:, 1] = 0. if all_wheels else -.25
    env.patch_bounds = torch.tensor([[0., 6.2, -3.1, 3.1]] if all_wheels else [[0., .4, -.2, .2]])
    env.traversal_bounds = torch.tensor([[-1.5, 7.7, -4.1, 4.1]] if all_wheels else [[-2., 3., -1., 1.]])
    env.terrain_x_min, env.terrain_x_max, env.terrain_y_min, env.terrain_y_max = env.traversal_bounds[0].tolist()
    env.selected_sides = torch.full((1,), 2 if all_wheels else 0, dtype=torch.long)
    env.travel_signs = torch.tensor([float(sign)])
    env.goal_directions = torch.tensor([[float(sign), 0.]])
    env.spawn_positions = env.root_states[:, :3].clone()
    env._wheel_center_offsets = torch.tensor([[.43, .25, -.4], [.43, -.25, -.4],
                                               [-.43, .25, -.4], [-.43, -.25, -.4]])
    env._wheel_default_half_extents = torch.tensor([[.11, .02, .11]]).repeat(4, 1)
    env._wheel_collision_offsets = torch.zeros(4, 3)
    env._wheel_collision_axes = torch.tensor([[0., 1., 0.]]).repeat(4, 1)
    env._wheel_radii = torch.full((4,), .11)
    env._wheel_widths = torch.full((4,), .04)
    env.measurement_wheel_indices = torch.arange(4)
    env.wheel_body_indices = torch.full((4,), -1)  # Legacy wrong mapping must not be used.
    env.rigid_state = torch.zeros(1, 5, 13)
    env.rigid_state[:, :, 6] = 1.
    env.rigid_state[:, 4, :3] = 999.
    env.contact_forces = torch.zeros(1, 5, 3)
    env.termination_contact_indices = torch.tensor([4])
    env.episode_length_buf[:] = 0
    env.max_episode_length = 100
    env._resample_commands(torch.tensor([0]))
    env._step_commands = env.commands[:, :3].clone()
    env._start(torch.tensor([0]))
    env.dof_state = torch.zeros(2, 2)
    env.dof_state[:, 1] = 2.
    env.torques = torch.ones(1, 2)
    return env


def advance(env, x, y=None):
    # This interval belongs to the old active mask, before entry detection.
    for _ in range(4):
        env._before_physics_substep()
        env._after_physics_substep()
    env.root_states[0, 0] = x
    if y is not None:
        env.root_states[0, 1] = y
    env.rigid_state[:, :4, :3] = env.root_states[:, None, :3] + env._wheel_center_offsets[None]
    env.root_states[:, 7] = env.travel_signs
    env.base_lin_vel[:, 0] = env.travel_signs
    env.episode_length_buf += 1
    env.check_termination()


class PatchEvaluationEnvTests(unittest.TestCase):
    def test_standard_all_wheels_window_keeps_raw_sampling_until_last_exit(self):
        env = patch_env(all_wheels=True)
        advance(env, -.5)
        self.assertEqual(env.crossing.wheels_entered_mask[0].tolist(), [True, True, False, False])
        self.assertEqual(env._attempt_metadata[0]["selected_side"], "all")
        self.assertEqual(env.physics_rows, [])
        advance(env, .5)
        self.assertTrue(env.crossing.wheels_entered_mask.all())
        advance(env, 6.1)
        self.assertFalse(env.reset_buf[0])
        advance(env, 6.7)  # The last row still overlaps the exit plane.
        self.assertFalse(env.reset_buf[0])
        advance(env, 6.75)
        self.assertEqual(env._episode_status[0], "success")
        env._finish_attempt(torch.tensor([0]), "success", env._episode_reason[0])
        self.assertEqual(len(env.control_rows), 4)
        self.assertEqual(len(env.physics_rows), 16)
        self.assertEqual(env.completed_episodes[0]["wheels_entered_mask"], [True] * 4)
        self.assertEqual(env.completed_episodes[0]["selected_side"], "all")
        self.assertTrue(all(bounds[0] >= 6.2 for bounds in env.completed_episodes[0]["terminal_wheel_bounds_xy"]))

    def test_standard_window_rejects_right_rear_bypass_after_other_wheels_enter(self):
        env = patch_env(all_wheels=True)
        env._wheel_center_offsets[3, 1] = 4.
        advance(env, -.5)
        advance(env, .5)
        advance(env, 6.75)
        self.assertEqual(env.crossing.wheels_entered_mask[0].tolist(), [True, True, True, False])
        self.assertEqual(env._episode_status[0], "failure")
        self.assertEqual(env._episode_reason[0], "bypass")

    def test_urdf_fk_and_collision_geometry_are_json_safe_and_match_robot(self):
        cfg = geometry_cfg()
        geometry = wheel_geometry_from_cfg(cfg)
        json.dumps(geometry)
        np.testing.assert_allclose(geometry["center_offsets"],
                                   [[.42596576598, .23621531514, -.40252671222],
                                    [.42594638235, -.26037980227, -.40254179047],
                                    [-.43603423402, .23621531514, -.40252671222],
                                    [-.43605361765, -.26037980227, -.40254179047]], atol=1e-9)
        self.assertEqual(geometry["radii"], [.11] * 4)
        self.assertEqual(geometry["widths"], [.04] * 4)
        self.assertAlmostEqual(geometry["wheel_x_max"] - geometry["wheel_x_min"], 1.08201938363)
        self.assertAlmostEqual(geometry["default_half_extents"][0][1], .03088175914)
        cfg.init_state.default_joint_angles["FL_thigh_joint"] += .1
        changed = wheel_geometry_from_cfg(cfg)
        self.assertNotEqual(changed["center_offsets"][0], geometry["center_offsets"][0])
        self.assertEqual(changed["center_offsets"][1:], geometry["center_offsets"][1:])

    def test_oriented_cylinder_projection_uses_width_axis_and_collision_offset(self):
        states = torch.zeros(1, 1, 13)
        states[0, 0, :3] = torch.tensor([3., 5., 20.])  # Height does not prevent projected entry.
        states[0, 0, 3:7] = torch.tensor([0., 0., 2 ** -.5, 2 ** -.5])
        bounds = project_wheel_cylinders(states, torch.tensor([[.1, 0., 0.]]),
                                         torch.tensor([[0., 1., 0.]]), torch.tensor([.11]), torch.tensor([.04]))
        torch.testing.assert_close(bounds, torch.tensor([[[2.98, 3.02, 4.99, 5.21]]]), atol=1e-5, rtol=1e-5)

    def test_entry_step_excluded_gap_kept_last_wheel_exit_recorded_once(self):
        env = patch_env()
        advance(env, -.7)
        self.assertFalse(env.metrics.active[0])
        advance(env, -.5)
        self.assertTrue(env.metrics.active[0])
        self.assertEqual(env.physics_rows, [])
        self.assertEqual(env.control_rows, [])
        self.assertEqual(env.metrics.elapsed_s[0], 0.)
        self.assertEqual(env.crossing.wheels_entered_mask[0].tolist(), [True, False, False, False])
        advance(env, .2)  # Front axle is beyond the patch; rear has not entered yet.
        self.assertFalse(env.reset_buf[0])
        self.assertTrue(env.metrics.active[0])
        self.assertAlmostEqual(env.metrics.elapsed_s[0].item(), .02)
        advance(env, .4)
        self.assertTrue(env.crossing.wheels_entered_mask[0, 2])
        advance(env, .95)
        self.assertTrue(env.reset_buf[0])
        self.assertEqual(env._episode_status[0], "success")
        env._finish_attempt(torch.tensor([0]), "success", env._episode_reason[0])
        row = env.completed_episodes[0]
        self.assertEqual(len(env.control_rows), 3)
        self.assertEqual(len(env.physics_rows), 12)
        self.assertAlmostEqual(offline_energy(env.physics_rows, 2), .24)
        for index, sample in enumerate(env.physics_rows):
            self.assertEqual(sample["control_step"], index // 4 + 1)
            self.assertEqual(sample["substep_index"], index % 4 + 1)
            self.assertGreater(sample["time_end_s"], 0.)
            self.assertLessEqual(sample["time_end_s"], .06 + 1e-12)
        self.assertAlmostEqual(row["elapsed_s"], .06)
        self.assertAlmostEqual(row["physics_elapsed_s"], .06)
        self.assertAlmostEqual(row["exit_time_s"] - row["entry_time_s"], row["elapsed_s"])
        path = sum(math.hypot(sample["world_x_m"] - sample["previous_world_x_m"],
                              sample["world_y_m"] - sample["previous_world_y_m"])
                   for sample in env.control_rows)
        self.assertAlmostEqual(path, 1.45, places=6)
        for calculated in ("path_xy_m", "energy_net_j", "mean_power_net_w", "cot_net_path",
                           "velocity_instability_rate", "tracking_rmse_xy_mps"):
            self.assertNotIn(calculated, row)
        self.assertTrue(row["window_started"])
        self.assertAlmostEqual(row["entry_base_position"][0], -.5)
        self.assertAlmostEqual(row["terminal_base_position"][0], .95)
        self.assertTrue(all(bounds[0] >= .4 for bounds in row["terminal_wheel_bounds_xy"]))
        self.assertAlmostEqual(row["window_end_time_s"], row["exit_time_s"])
        self.assertEqual(row["wheel_contact_mask"], [False] * 4)  # Jumping/projection need not touch.
        self.assertEqual(env.episode_counts[0], 1)

    def test_reverse_keeps_yaw_zero_and_rear_axle_enters_first(self):
        env = patch_env(sign=-1)
        self.assertEqual(env.commands[0, 0], -1.)
        advance(env, .9)
        self.assertTrue(env.metrics.active[0])
        self.assertEqual(env.crossing.wheels_entered_mask[0].tolist(), [False, False, True, False])
        advance(env, .2)
        self.assertFalse(env.reset_buf[0])
        advance(env, -.1)
        advance(env, -.6)
        self.assertEqual(env._episode_status[0], "success")
        torch.testing.assert_close(env.root_states[0, 3:7], torch.tensor([0., 0., 0., 1.]))
        self.assertEqual(env._attempt_metadata[0]["leading_axle"], "rear")

    def test_before_entry_timeout_has_attempt_but_no_physical_measurements(self):
        env = patch_env()
        env.max_episode_length = 1
        advance(env, -.7)
        self.assertEqual(env._episode_status[0], "timeout")
        env._finish_attempt(torch.tensor([0]), "timeout", "time_limit")
        row = env.completed_episodes[0]
        self.assertFalse(row["window_started"])
        self.assertEqual(env.physics_rows, [])
        self.assertEqual(env.control_rows, [])
        self.assertIsNone(row["elapsed_s"])
        self.assertEqual(row["mass_kg"], 15.)
        self.assertEqual(row["gravity_m_s2"], 9.81)
        self.assertNotIn("success_rate", row)

    def test_bypass_retreat_fall_and_corridor_exit_have_distinct_reasons(self):
        with self.subTest("bypass"):
            env = patch_env()
            advance(env, -.7, y=.5)
            advance(env, 1., y=.5)
            self.assertEqual(env._episode_reason[0], "bypass")
            self.assertFalse(env.metrics.active[0])
        with self.subTest("retreat"):
            env = patch_env()
            advance(env, -.5)
            advance(env, -.8)
            self.assertEqual(env._episode_reason[0], "retreat")
            self.assertTrue(env.metrics.active[0])
        with self.subTest("fall"):
            env = patch_env()
            env.projected_gravity[0, 2] = 0.
            advance(env, -.7)
            self.assertEqual(env._episode_reason[0], "fall")
        with self.subTest("out_of_corridor"):
            env = patch_env()
            advance(env, -.7, y=1.1)
            self.assertEqual(env._episode_reason[0], "out_of_corridor")

    def test_invalid_velocity_at_first_entry_records_failure_without_start_error(self):
        env = patch_env()
        env.root_states[0, 0] = -.5
        env.root_states[0, 7] = float("nan")
        env.rigid_state[:, :4, :3] = env.root_states[:, None, :3] + env._wheel_center_offsets[None]
        env.episode_length_buf += 1
        env.check_termination()
        self.assertEqual(env._episode_reason[0], "nonfinite_state")
        self.assertFalse(env.metrics.active[0])
        env._finish_attempt(torch.tensor([0]), "failure", "nonfinite_state")
        self.assertFalse(env.completed_episodes[0]["window_started"])
        self.assertIsNone(env.completed_episodes[0]["window_end_time_s"])

    def test_crossing_in_one_control_step_is_marked_without_fake_samples(self):
        env = patch_env()
        advance(env, 1.)
        self.assertEqual(env._episode_status[0], "success")
        env._finish_attempt(torch.tensor([0]), "success", "all_wheels_cleared")
        row = env.completed_episodes[0]
        self.assertTrue(row["window_started"])
        self.assertTrue(row["window_zero_duration"])
        self.assertEqual(row["elapsed_s"], 0.)
        self.assertEqual(env.physics_rows, [])
        self.assertEqual(env.control_rows, [])
        self.assertNotIn("energy_net_j", row)

    def test_new_attempt_is_reset_before_measuring_and_side_selection_is_balanced(self):
        env = patch_env(quota=2)
        env.max_episode_length = 1
        advance(env, -.7)

        def reset(_self, ids):
            self.assertEqual(len(env.completed_episodes), 1)
            self.assertFalse(env.attempt_active[0])
            env.root_states[ids, 0] = -.8
            env.episode_length_buf[ids] = 0

        with patch.object(Nezha2FreeEnv, "reset_idx", side_effect=reset), patch.object(env, "_sync_reset_state"):
            env.reset_idx(torch.tensor([0]))
        self.assertTrue(env.attempt_active[0])
        self.assertFalse(env.metrics.active[0])
        self.assertFalse(env.crossing.window_started[0])
        self.assertEqual(env._attempt_metadata[0]["episode_index"], 1)
        env.interrupt("test")
        self.assertEqual([row["status"] for row in env.completed_episodes], ["timeout", "interrupted"])
        self.assertFalse(env.evaluation_complete)

    def test_explicit_window_resets_keep_raw_attempt_keys_unique_and_quota_intact(self):
        env = patch_env(quota=1)

        def physical_reset(_self, ids):
            env.root_states[ids, 0], env.episode_length_buf[ids] = -.8, 0

        with patch.object(Nezha2FreeEnv, "reset_idx", side_effect=physical_reset), \
                patch.object(env, "_sync_reset_state"):
            for _ in range(2):
                advance(env, -.5)
                advance(env, .2)
                env.reset_idx(torch.tensor([0]))
                self.assertEqual(env.episode_counts[0], 0)
                self.assertFalse(env.evaluation_complete)
            env.max_episode_length = 1
            advance(env, -.7)  # The third attempt ends without entering the window.
            env.reset_idx(torch.tensor([0]))

        self.assertEqual([row["episode_index"] for row in env.completed_episodes], [0, 1, 2])
        self.assertEqual([row["status"] for row in env.completed_episodes],
                         ["interrupted", "interrupted", "timeout"])
        self.assertEqual([(row["episode_index"], row["control_step"]) for row in env.control_rows],
                         [(0, 1), (1, 1)])
        self.assertEqual([(row["episode_index"], row["physics_step"]) for row in env.physics_rows],
                         [(attempt, step) for attempt in (0, 1) for step in range(1, 5)])
        self.assertFalse(env.completed_episodes[-1]["window_started"])
        self.assertEqual(env.episode_counts[0], 1)
        self.assertTrue(env.evaluation_complete)

    def test_standard_default_spawns_center_full_footprint_and_use_actual_ground_height(self):
        geometry = wheel_geometry_from_cfg(geometry_cfg())
        for sign in (1, -1):
            with self.subTest(direction=sign):
                env = patch_env(sign=sign, all_wheels=True)
                del env.evaluation.wheel_side  # Production fallback must be all.
                cfg = NS(mesh_type="heightfield", type_names=("slope",),
                         terrain_length=6.2, terrain_width=6.2, horizontal_scale=.02,
                         vertical_scale=.005, border_size=2., corridor_width=8.2,
                         **{key: geometry[key] for key in ("left_wheel_y", "right_wheel_y", "front_wheel_x",
                             "rear_wheel_x", "wheel_radius", "wheel_x_min", "wheel_x_max", "wheel_y_min", "wheel_y_max")})
                env.terrain = PatchEvaluationTerrain(cfg, 1)
                env.base_init_state = torch.tensor([0., 0., .6, 0., 0., 0., 1., 0., 0., 0., 0., 0., 0.])
                env._spawn_rngs = [np.random.default_rng(123)]
                env.gym, env.sim = NS(set_actor_root_state_tensor_indexed=Mock()), object()
                with patch("wheel_legged_gym.evaluation.patch_env.gymtorch.unwrap_tensor", side_effect=lambda x: x), \
                        patch.object(env.terrain, "sample_spawns", wraps=env.terrain.sample_spawns) as sample:
                    env._reset_root_states(torch.tensor([0]))
                self.assertEqual(sample.call_args.kwargs["side"], "center")
                self.assertEqual(env.selected_sides[0], 2)
                bounds = env.patch_bounds[0]
                x, y, z = env.root_states[0, :3].tolist()
                self.assertLessEqual(abs(y - float((bounds[2] + bounds[3]) * .5)), .040001)
                self.assertGreater(y + geometry["wheel_y_min"], bounds[2])
                self.assertLess(y + geometry["wheel_y_max"], bounds[3])
                if sign > 0:
                    self.assertLess(x + geometry["wheel_x_max"], bounds[0])
                else:
                    self.assertGreater(x + geometry["wheel_x_min"], bounds[1])
                    self.assertGreater(z, .6)
                height = env.terrain.ground_heights(np.asarray([[x, y]]))[0]
                self.assertAlmostEqual(z, height + .6, places=6)
                self.assertEqual(env.commands[0, 0], float(sign))
                torch.testing.assert_close(env.root_states[0, 3:7], torch.tensor([0., 0., 0., 1.]))


if __name__ == "__main__":
    unittest.main()
