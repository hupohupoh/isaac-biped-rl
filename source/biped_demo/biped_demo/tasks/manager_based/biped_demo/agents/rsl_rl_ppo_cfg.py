"""PPO configuration for the bipedal robot velocity tracking task.

The observation and action dimensions scale with the number of joints (12 DOF).
Critic is deeper than the Go2 config for better value estimation on the harder bipedal task.
"""

from isaaclab.utils.configclass import configclass

from isaaclab_rl.rsl_rl import (
    RslRlMLPModelCfg,
    RslRlOnPolicyRunnerCfg,
    RslRlPpoAlgorithmCfg,
)


@configclass
class PPORunnerCfg(RslRlOnPolicyRunnerCfg):
    """PPO runner configuration for bipedal locomotion."""

    num_steps_per_env = 124
    max_iterations = 50000
    save_interval = 100
    experiment_name = "biped_demo"
    empirical_normalization = False

    # Actor network: deep enough for bipedal locomotion
    actor = RslRlMLPModelCfg(
        hidden_dims=[512, 256, 128],
        activation="elu",
        obs_normalization=False,
        distribution_cfg=RslRlMLPModelCfg.GaussianDistributionCfg(init_std=1.0),
    )

    # Critic network: deeper than Go2 for better value estimation
    critic = RslRlMLPModelCfg(
        hidden_dims=[256, 128, 64],
        activation="elu",
        obs_normalization=False,
    )

    # PPO hyperparameters
    algorithm = RslRlPpoAlgorithmCfg(
        value_loss_coef=1.0,
        use_clipped_value_loss=True,
        clip_param=0.2,
        entropy_coef=0.001,        # low — let the reward signal dominate over randomness
        num_learning_epochs=5,
        num_mini_batches=4,
        learning_rate=1.0e-3,
        schedule="adaptive",
        gamma=0.99,
        lam=0.95,
        desired_kl=0.01,
        max_grad_norm=1.0,
    )
