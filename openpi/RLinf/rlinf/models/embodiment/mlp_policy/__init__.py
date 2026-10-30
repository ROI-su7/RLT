# Copyright 2025 The RLinf Authors.
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     https://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.

import torch
from omegaconf import DictConfig


def get_model(cfg: DictConfig, torch_dtype=torch.bfloat16):
    from rlinf.models.embodiment.mlp_policy.iql_mlp_policy import IQLMLPPolicy
    from rlinf.models.embodiment.mlp_policy.mlp_policy import MLPPolicy
    from rlinf.models.embodiment.mlp_policy.rlt_mlp_policy import RLTMLPPolicy

    iql_config = cfg.get("iql_config", None)
    if cfg.model_type == "rlt_mlp_policy":
        model = RLTMLPPolicy(
            z_dim=cfg.z_dim,
            proprio_dim=cfg.proprio_dim,
            action_dim=cfg.action_dim,
            num_action_chunks=cfg.num_action_chunks,
            ref_num_action_chunks=cfg.get(
                "ref_num_action_chunks", cfg.num_action_chunks
            ),
            add_q_head=cfg.get("add_q_head", True),
            q_head_type=cfg.get("q_head_type", "default"),
            fixed_std=cfg.get("fixed_std", 0.002),
            fixed_gripper_std=cfg.get("fixed_gripper_std", 0.0002),
            fixed_std_is_normalized=cfg.get("fixed_std_is_normalized", False),
            execute_actor_mean=cfg.get("execute_actor_mean", False),
            actor_hidden_dim=cfg.get("actor_hidden_dim", 256),
            actor_num_layers=cfg.get("actor_num_layers", 2),
            action_norm_stats=cfg.get("action_norm_stats", None),
            actor_architecture=cfg.get("actor_architecture", "mlp"),
            critic_hidden_dim=cfg.get("critic_hidden_dim", 256),
            critic_num_layers=cfg.get("critic_num_layers", 2),
            actor_output=cfg.get("actor_output", "full"),
            bridge_delta_dim=cfg.get("bridge_delta_dim", 0),
            bridge_delta_scale=cfg.get("bridge_delta_scale", 0.05),
            head_pose_dim=cfg.get("head_pose_dim", 0),
            head_pose_scale=cfg.get("head_pose_scale", None),
        )
    elif iql_config is not None:
        model = IQLMLPPolicy(
            cfg.obs_dim,
            cfg.action_dim,
            num_action_chunks=cfg.num_action_chunks,
            add_value_head=cfg.add_value_head,
            add_q_head=cfg.get("add_q_head", False),
            q_head_type=cfg.get("q_head_type", "default"),
        )
        model.configure_iql(iql_config)
    else:
        model = MLPPolicy(
            cfg.obs_dim,
            cfg.action_dim,
            num_action_chunks=cfg.num_action_chunks,
            add_value_head=cfg.add_value_head,
            add_q_head=cfg.get("add_q_head", False),
            q_head_type=cfg.get("q_head_type", "default"),
        )

    return model
