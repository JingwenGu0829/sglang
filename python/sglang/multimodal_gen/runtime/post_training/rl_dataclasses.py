# SPDX-License-Identifier: Apache-2.0
"""RL-specific dataclasses used by post-training and rollout paths."""

from dataclasses import dataclass, field
from typing import Any

import torch


@dataclass
class RolloutSessionData:
    """Per-batch rollout state created by prepare_rollout(), lives on the batch object.

    Cleared by setting ``batch._rollout_session_data = None``.
    """

    pipeline_config: Any = None
    sigma_max: float = 0.0
    latents_shape: tuple | None = None
    noise_buffer: torch.Tensor | None = None

    local_log_prob_sum: list[torch.Tensor] = field(default_factory=list)
    local_log_prob_count: list[torch.Tensor] = field(default_factory=list)

    local_variance_noises: list[torch.Tensor] = field(default_factory=list)
    local_prev_sample_means: list[torch.Tensor] = field(default_factory=list)
    local_noise_std_devs: list[torch.Tensor] = field(default_factory=list)
    local_model_outputs: list[torch.Tensor] = field(default_factory=list)


@dataclass
class RolloutDebugTensors:
    """Container for rollout debug tensors collected during denoising."""

    rollout_variance_noises: torch.Tensor | None = None
    rollout_prev_sample_means: torch.Tensor | None = None
    rollout_noise_std_devs: torch.Tensor | None = None
    rollout_model_outputs: torch.Tensor | None = None


@dataclass
class RolloutDenoisingEnv:
    image_kwargs: dict[str, Any] | None = None
    pos_cond_kwargs: dict[str, Any] | None = None
    neg_cond_kwargs: dict[str, Any] | None = None
    guidance: torch.Tensor | None = None


@dataclass
class RolloutDitTrajectory:
    # [B, K, ...]: retained joint boundaries, indexed by latent_step_indices.
    # Full capture includes the N pre-update states and the final state.
    latents: torch.Tensor | None = None
    # Full [N+1] rollout clock in named streams; retained [K] in legacy dit_trajectory.
    timesteps: torch.Tensor | None = None
    # Full [N+1] sigma schedule, independent of sparse latent capture.
    sigmas: torch.Tensor | None = None
    # Original loop-boundary indices for retained latents, independent of the
    # full timesteps/sigmas arrays. Required when capture is sparse.
    latent_step_indices: torch.Tensor | None = None
    # Actual model clock when it differs from the exported rollout clock (H3).
    model_timesteps: torch.Tensor | None = None


@dataclass
class RolloutTrajectoryData:
    rollout_log_probs: torch.Tensor | None = None
    rollout_debug_tensors: RolloutDebugTensors | None = None
    denoising_env: RolloutDenoisingEnv | None = None
    dit_trajectory: RolloutDitTrajectory | None = None
    # Additive multi-stream output. dit_trajectory remains the video projection.
    stream_trajectories: dict[str, RolloutDitTrajectory] = field(default_factory=dict)
