# Copyright (c) 2025, The Isaac Lab Project Developers (https://github.com/isaac-sim/IsaacLab/blob/main/CONTRIBUTORS.md).
# All rights reserved.
#
# SPDX-License-Identifier: BSD-3-Clause

from isaaclab.utils.configclass import configclass

from isaaclab_rl.rsl_rl import RslRlMLPModelCfg, RslRlOnPolicyRunnerCfg, RslRlPpoAlgorithmCfg


@configclass
class LeapCubePPORunnerCfg(RslRlOnPolicyRunnerCfg):
    num_steps_per_env = 24
    max_iterations = 5000
    save_interval = 50
    experiment_name = "leap_cube"
    actor = RslRlMLPModelCfg(
        hidden_dims=[512, 256, 128],
        activation="elu",
        obs_normalization=True,
        distribution_cfg=RslRlMLPModelCfg.GaussianDistributionCfg(init_std=1.0),
    )
    critic = RslRlMLPModelCfg(
        hidden_dims=[512, 256, 128],
        activation="elu",
        obs_normalization=True,
    )
    algorithm = RslRlPpoAlgorithmCfg(
        value_loss_coef=1.0,
        use_clipped_value_loss=True,
        clip_param=0.2,
        entropy_coef=0.002,
        num_learning_epochs=5,
        num_mini_batches=4,
        learning_rate=0.001,
        schedule="adaptive",
        gamma=0.998,
        lam=0.95,
        desired_kl=0.01,
        max_grad_norm=1.0,
    )

    # rsl_rl 5.0.1's MLPModel rejects the deprecated rsl_rl<4 fields that RslRlMLPModelCfg
    # still declares (they serialize into cfg["actor"]/cfg["critic"] and reach the model
    # constructor as unexpected kwargs). Drop them so OnPolicyRunner receives a clean dict.
    _DEPRECATED_MODEL_FIELDS = ("stochastic", "init_noise_std", "noise_std_type", "state_dependent_std")

    def __post_init__(self):
        for model_cfg in (self.actor, self.critic):
            for field in self._DEPRECATED_MODEL_FIELDS:
                if hasattr(model_cfg, field):
                    delattr(model_cfg, field)
