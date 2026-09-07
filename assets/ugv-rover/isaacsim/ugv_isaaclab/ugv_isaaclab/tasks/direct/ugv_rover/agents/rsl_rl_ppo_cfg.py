"""PPO configurations for UGV rover navigation tasks."""

from isaaclab.utils.configclass import configclass
from isaaclab_rl.rsl_rl import RslRlMLPModelCfg, RslRlOnPolicyRunnerCfg, RslRlPpoAlgorithmCfg


@configclass
class UGVRoverEmptyPPORunnerCfg(RslRlOnPolicyRunnerCfg):
    """Small PPO runner for the first empty-rectangle training pass."""

    num_steps_per_env = 32
    max_iterations = 500
    save_interval = 50
    experiment_name = "ugv_rover_empty"
    empirical_normalization = False
    clip_actions = 1.0

    actor = RslRlMLPModelCfg(
        hidden_dims=[128, 128],
        activation="elu",
        obs_normalization=True,
        distribution_cfg=RslRlMLPModelCfg.GaussianDistributionCfg(init_std=0.6),
    )
    critic = RslRlMLPModelCfg(
        hidden_dims=[128, 128],
        activation="elu",
        obs_normalization=True,
    )
    algorithm = RslRlPpoAlgorithmCfg(
        value_loss_coef=1.0,
        use_clipped_value_loss=True,
        clip_param=0.2,
        entropy_coef=0.01,
        num_learning_epochs=5,
        num_mini_batches=4,
        learning_rate=3.0e-4,
        schedule="adaptive",
        gamma=0.99,
        lam=0.95,
        desired_kl=0.01,
        max_grad_norm=1.0,
    )


@configclass
class UGVRoverCityPPORunnerCfg(UGVRoverEmptyPPORunnerCfg):
    """Continue PPO from the empty-space policy in the static city arena."""

    max_iterations = 600
    save_interval = 50
    experiment_name = "ugv_rover_city_static"
    algorithm = RslRlPpoAlgorithmCfg(
        value_loss_coef=1.0,
        use_clipped_value_loss=True,
        clip_param=0.2,
        entropy_coef=0.003,
        num_learning_epochs=5,
        num_mini_batches=4,
        learning_rate=1.0e-4,
        schedule="adaptive",
        gamma=0.99,
        lam=0.95,
        desired_kl=0.006,
        max_grad_norm=1.0,
    )
