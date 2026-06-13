# Copyright (c) 2022-2026, The Isaac Lab Project Developers (https://github.com/isaac-sim/IsaacLab/blob/main/CONTRIBUTORS.md).
# All rights reserved.
#
# SPDX-License-Identifier: BSD-3-Clause

from isaaclab.utils import configclass

from isaaclab_rl.rsl_rl import (
    RslRlOnPolicyRunnerCfg,
    RslRlPpoActorCriticCfg,
    RslRlPpoAlgorithmCfg,
    RslRlEncoderModelCfg,
    RslRlMLPModelCfg,
)


@configclass
class NavigationEnvPPORunnerCfg(RslRlOnPolicyRunnerCfg):
    num_steps_per_env = 8
    max_iterations = 1500
    save_interval = 50
    experiment_name = "anymal_c_navigation"
    policy = RslRlPpoActorCriticCfg(
        init_noise_std=0.5,
        actor_obs_normalization=False,
        critic_obs_normalization=False,
        actor_hidden_dims=[128, 128],
        critic_hidden_dims=[128, 128],
        activation="elu",
    )
    algorithm = RslRlPpoAlgorithmCfg(
        value_loss_coef=1.0,
        use_clipped_value_loss=True,
        clip_param=0.2,
        entropy_coef=0.005,
        num_learning_epochs=5,
        num_mini_batches=4,
        learning_rate=1.0e-3,
        schedule="adaptive",
        gamma=0.99,
        lam=0.95,
        desired_kl=0.01,
        max_grad_norm=1.0,
    )
    logger="wandb"
    wandb_project="anymal navigation"

@configclass
class NavigationEnvModPPORunnerCfg(RslRlOnPolicyRunnerCfg):
    num_steps_per_env = 8
    max_iterations = 1500
    save_interval = 50
    experiment_name = "anymal_c_navigation_mod"
    empirical_normalization = False
    obs_groups = {"actor": ["policy"], "critic": ["policy"]}
    actor = RslRlEncoderModelCfg(
        hidden_dims=[128, 128],
        activation="elu",
        distribution_cfg=RslRlEncoderModelCfg.GaussianDistributionCfg(init_std=0.5, std_type="scalar"),
        encoder_dims=None,
        tanh_output=True,
    )
    critic = RslRlMLPModelCfg(hidden_dims=[128, 128], activation="elu", distribution_cfg=None)
    algorithm = RslRlPpoAlgorithmCfg(
        value_loss_coef=1.0,
        use_clipped_value_loss=True,
        clip_param=0.2,
        entropy_coef=0.005,
        num_learning_epochs=5,
        num_mini_batches=4,
        learning_rate=1.0e-3,
        schedule="adaptive",
        gamma=0.99,
        lam=0.95,
        desired_kl=0.01,
        max_grad_norm=1.0,
    )
    logger="wandb"
    wandb_project="anymal navigation"
