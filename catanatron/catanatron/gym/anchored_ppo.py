"""Maskable PPO with a frozen behavioural-cloning policy anchor."""

from __future__ import annotations

import copy
from typing import Any

import numpy as np
import torch as th
from gymnasium import spaces
from sb3_contrib import MaskablePPO  # type: ignore[import-untyped]
from stable_baselines3.common.utils import explained_variance
from torch.nn import functional as F


def legal_action_forward_kl(
    reference_logits: th.Tensor,
    current_logits: th.Tensor,
    action_masks: th.Tensor,
) -> th.Tensor:
    """Return ``KL(reference || current)`` over legal actions only.

    The reference distribution is the teacher. Consequently, minimizing this
    direction penalizes the current actor for dropping actions that retained
    probability under the BC policy. Illegal actions have no effect on either
    the value or the gradient.
    """

    if reference_logits.shape != current_logits.shape:
        raise ValueError("Reference and current logits must have the same shape")
    if action_masks.shape != current_logits.shape:
        raise ValueError("Action masks must have the same shape as the logits")

    legal = action_masks.to(device=current_logits.device, dtype=th.bool)
    floor = th.finfo(current_logits.dtype).min
    reference_log_probs = F.log_softmax(
        reference_logits.to(current_logits.device).masked_fill(~legal, floor), dim=-1
    )
    current_log_probs = F.log_softmax(current_logits.masked_fill(~legal, floor), dim=-1)
    reference_probs = reference_log_probs.exp()
    terms = reference_probs * (reference_log_probs - current_log_probs)
    return th.where(legal, terms, th.zeros_like(terms)).sum(dim=-1).mean()


class AnchoredMaskablePPO(MaskablePPO):
    """MaskablePPO whose actor stays close to a frozen reference policy."""

    def __init__(self, *args: Any, bc_anchor_coef: float = 0.0, **kwargs: Any):
        if bc_anchor_coef < 0:
            raise ValueError("bc_anchor_coef must be non-negative")
        self.bc_anchor_coef = float(bc_anchor_coef)
        self.anchor_policy = None
        super().__init__(*args, **kwargs)

    def _excluded_save_params(self) -> list[str]:
        # The reference duplicates the policy weights and is needed only while
        # training. Excluding it keeps ordinary MaskablePPO inference artifacts.
        return [*super()._excluded_save_params(), "anchor_policy"]

    def set_anchor_from_current_policy(self) -> None:
        """Freeze a snapshot of the actor currently loaded into ``self.policy``."""

        self.anchor_policy = copy.deepcopy(self.policy).to(self.device)
        self.anchor_policy.set_training_mode(False)
        for parameter in self.anchor_policy.parameters():
            parameter.requires_grad_(False)

    def _bc_anchor_kl(
        self, observations: th.Tensor, action_masks: th.Tensor
    ) -> th.Tensor:
        if self.anchor_policy is None:
            raise RuntimeError(
                "BC anchoring is enabled but no reference policy was frozen"
            )
        with th.no_grad():
            reference = self.anchor_policy.get_distribution(
                observations, action_masks=action_masks
            ).distribution
        current = self.policy.get_distribution(
            observations, action_masks=action_masks
        ).distribution
        return legal_action_forward_kl(reference.logits, current.logits, action_masks)

    def train(self) -> None:
        """Update the policy with PPO plus legal-action BC retention loss."""

        self.policy.set_training_mode(True)
        self._update_learning_rate(self.policy.optimizer)
        clip_range = self.clip_range(self._current_progress_remaining)
        if self.clip_range_vf is not None:
            clip_range_vf = self.clip_range_vf(self._current_progress_remaining)

        entropy_losses: list[float] = []
        pg_losses: list[float] = []
        value_losses: list[float] = []
        anchor_losses: list[float] = []
        clip_fractions: list[float] = []
        continue_training = True
        loss = th.zeros((), device=self.device)
        approx_kl_divs: list[np.ndarray] = []

        for epoch in range(self.n_epochs):
            approx_kl_divs = []
            for rollout_data in self.rollout_buffer.get(self.batch_size):
                actions = rollout_data.actions
                if isinstance(self.action_space, spaces.Discrete):
                    actions = actions.long().flatten()

                values, log_prob, entropy = self.policy.evaluate_actions(
                    rollout_data.observations,
                    actions,
                    action_masks=rollout_data.action_masks,
                )
                values = values.flatten()
                advantages = rollout_data.advantages
                if self.normalize_advantage:
                    advantages = (advantages - advantages.mean()) / (
                        advantages.std() + 1e-8
                    )

                ratio = th.exp(log_prob - rollout_data.old_log_prob)
                policy_loss_1 = advantages * ratio
                policy_loss_2 = advantages * th.clamp(
                    ratio, 1 - clip_range, 1 + clip_range
                )
                policy_loss = -th.min(policy_loss_1, policy_loss_2).mean()
                pg_losses.append(policy_loss.item())
                clip_fractions.append(
                    th.mean((th.abs(ratio - 1) > clip_range).float()).item()
                )

                if self.clip_range_vf is None:
                    values_pred = values
                else:
                    values_pred = rollout_data.old_values + th.clamp(
                        values - rollout_data.old_values,
                        -clip_range_vf,
                        clip_range_vf,
                    )
                value_loss = F.mse_loss(rollout_data.returns, values_pred)
                value_losses.append(value_loss.item())

                if entropy is None:
                    entropy_loss = -th.mean(-log_prob)
                else:
                    entropy_loss = -th.mean(entropy)
                entropy_losses.append(entropy_loss.item())

                loss = (
                    policy_loss
                    + self.ent_coef * entropy_loss
                    + self.vf_coef * value_loss
                )
                if self.bc_anchor_coef > 0:
                    anchor_loss = self._bc_anchor_kl(
                        rollout_data.observations, rollout_data.action_masks
                    )
                    anchor_losses.append(anchor_loss.item())
                    loss = loss + self.bc_anchor_coef * anchor_loss

                with th.no_grad():
                    log_ratio = log_prob - rollout_data.old_log_prob
                    approx_kl_div = (
                        th.mean((th.exp(log_ratio) - 1) - log_ratio).cpu().numpy()
                    )
                    approx_kl_divs.append(approx_kl_div)

                if self.target_kl is not None and approx_kl_div > 1.5 * self.target_kl:
                    continue_training = False
                    if self.verbose >= 1:
                        print(
                            f"Early stopping at step {epoch} due to reaching "
                            f"max kl: {approx_kl_div:.2f}"
                        )
                    break

                self.policy.optimizer.zero_grad()
                loss.backward()
                th.nn.utils.clip_grad_norm_(
                    self.policy.parameters(), self.max_grad_norm
                )
                self.policy.optimizer.step()

            self._n_updates += 1
            if not continue_training:
                break

        explained_var = explained_variance(
            self.rollout_buffer.values.flatten(), self.rollout_buffer.returns.flatten()
        )
        self.logger.record("train/entropy_loss", np.mean(entropy_losses))
        self.logger.record("train/policy_gradient_loss", np.mean(pg_losses))
        self.logger.record("train/value_loss", np.mean(value_losses))
        self.logger.record("train/approx_kl", np.mean(approx_kl_divs))
        self.logger.record("train/clip_fraction", np.mean(clip_fractions))
        self.logger.record("train/loss", loss.item())
        self.logger.record("train/explained_variance", explained_var)
        self.logger.record("train/n_updates", self._n_updates, exclude="tensorboard")
        self.logger.record("train/clip_range", clip_range)
        self.logger.record("train/bc_anchor_coef", self.bc_anchor_coef)
        if anchor_losses:
            self.logger.record("train/bc_anchor_kl", np.mean(anchor_losses))
        if self.clip_range_vf is not None:
            self.logger.record("train/clip_range_vf", clip_range_vf)
