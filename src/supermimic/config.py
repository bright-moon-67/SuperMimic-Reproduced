"""All training configuration in one dataclass tree (tyro-friendly)."""

from __future__ import annotations

from dataclasses import dataclass, field
from pathlib import Path

from supermimic.imagination.policy_trainer import PolicyTrainerCfg
from supermimic.policy.nets import CriticCfg, PolicyCfg
from supermimic.world_model.wm_trainer import WMTrainerCfg
from supermimic.world_model.world_model import WorldModelCfg


@dataclass
class DataCfg:
    npz_dir: Path = Path("data/npz/lafan1")
    clips: list[str] | None = None  # None = all npz in npz_dir
    limit: int | None = None
    manifest: Path | None = None  # csv with name,keep (filter_bones_seed.py output)
    library: Path | None = None  # packed compact library (.pt from build_library.py); overrides npz_dir


@dataclass
class EnvCfg:
    num_envs: int = 4096
    episode_length_s: float = 10.0
    action_noise_std: float = 0.1
    obs_noise: bool = True
    reset_noise: bool = True
    domain_randomization: bool = True
    sampling_mode: str = "return"
    replay_capacity: int = 1000
    future_frames: int = 10
    compact_library: bool = False
    anchor_obs: bool = False


@dataclass
class ScheduleCfg:
    total_iterations: int = 320_000  # env steps (plan D12 reading A)
    updates_per_env_step: float = 0.4  # UTD
    # plan7 scheme B: repeat WM updates per actor update.  1 keeps the
    # upstream 1:1 ratio; 2 or 4 tests whether the WM can track the changing
    # policy distribution.
    wm_updates_per_policy_update: int = 1
    policy_updates_per_wm_update: int = 1
    # Optional plan8 stage: keep collecting and updating the WM while Actor/Critic
    # remain frozen for this many env iterations.  0 preserves the old schedule.
    wm_only_iterations: int = 0
    warmup_iterations: int = 40  # env steps before the first update (fills k-step windows)
    lr_final_ratio: float = 0.03
    lr_decay_fraction: float = 250_000 / 320_000
    log_interval: int = 50  # iterations
    checkpoint_interval: int = 4000  # iterations
    keep_checkpoints: int = 4  # rotate numbered checkpoints, keep the most recent N
    max_hours: float | None = None


@dataclass
class TrainConfig:
    run_name: str = "debug"
    log_root: Path = Path("logs")
    seed: int = 0
    device: str = "cuda:0"
    data: DataCfg = field(default_factory=DataCfg)
    env: EnvCfg = field(default_factory=EnvCfg)
    world_model: WorldModelCfg = field(default_factory=WorldModelCfg)
    wm_trainer: WMTrainerCfg = field(default_factory=WMTrainerCfg)
    policy: PolicyCfg = field(default_factory=PolicyCfg)
    critic: CriticCfg = field(default_factory=CriticCfg)
    policy_trainer: PolicyTrainerCfg = field(default_factory=PolicyTrainerCfg)
    schedule: ScheduleCfg = field(default_factory=ScheduleCfg)
    resume: Path | None = None
    # Optional shared fixed 32-step evaluation windows (WindowBatch .pt).
    eval_windows: Path | None = None
    # full: restore weights + optimizers + iteration; transfer_policy: load Actor/Critic
    # weights only and reset WM/optimizers/schedule; wm_only: restore WM + wm optimizer.
    resume_mode: str = "full"
    # Comma-separated state-dict keys to skip on resume (e.g. "wm" to reuse a trained policy/critic
    # under a different world model). Supported: wm, policy, critic, wm_opt, policy_opt, critic_opt.
    resume_skip: str = ""
