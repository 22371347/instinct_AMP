import os

from isaaclab.utils import configclass

from instinctlab.utils.wrappers.instinct_rl import (
    InstinctRlActorCriticCfg,
    InstinctRlNormalizerCfg,
    InstinctRlOnPolicyRunnerCfg,
    InstinctRlPpoAlgorithmCfg,
)


@configclass
class PolicyCfg(InstinctRlActorCriticCfg):
    """PHP-style privileged teacher: MLP only (height scan + proprio, no depth CNN)."""

    init_noise_std = 1.0
    actor_hidden_dims = [512, 256, 128]
    critic_hidden_dims = [512, 256, 128]
    activation = "elu"


@configclass
class AlgorithmCfg(InstinctRlPpoAlgorithmCfg):
    class_name = "PPO"
    value_loss_coef = 1.0
    use_clipped_value_loss = True
    clip_param = 0.2
    entropy_coef = 0.005
    num_learning_epochs = 5
    num_mini_batches = 4
    learning_rate = 1e-3
    schedule = "adaptive"
    gamma = 0.99
    lam = 0.95
    desired_kl = 0.01
    max_grad_norm = 1.0


@configclass
class NormalizersCfg:
    policy: InstinctRlNormalizerCfg = InstinctRlNormalizerCfg()
    critic: InstinctRlNormalizerCfg = InstinctRlNormalizerCfg()


@configclass
class G1PerceptiveVaultPPORunnerCfg(InstinctRlOnPolicyRunnerCfg):
    policy: PolicyCfg = PolicyCfg()
    algorithm: AlgorithmCfg = AlgorithmCfg()
    normalizers: NormalizersCfg = NormalizersCfg()

    num_steps_per_env = 24
    max_iterations = 50000
    #: ⚠️ 2026-10-16：`1000` → `200`。1000 轮的间隔太粗（≈100 分钟才出一份），
    #: 回放/评估时几乎没有可选的中间点，且"第一个可用 ckpt"要等近两小时。
    #: 6 s/iter ⇒ 200 轮 ≈ 20 分钟一份；跑满 50000 轮共 250 份 × ~10.5 MB ≈ 2.6 GB（可接受）。
    save_interval = 200
    log_interval = 10
    experiment_name = "g1_perceptive_vault_shadowing"

    load_run = None

    def __post_init__(self):
        post_init = getattr(super(), "__post_init__", None)
        if post_init is not None:
            post_init()
        self.resume = self.load_run is not None
        self.run_name = "".join(
            [
                f"_GPU{os.environ.get('CUDA_VISIBLE_DEVICES')}" if "CUDA_VISIBLE_DEVICES" in os.environ else "",
            ]
        )
