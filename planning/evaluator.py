"""Trajectory-consistent TD-MPC2 World Model evaluation."""

from __future__ import annotations

import torch

from mpr_mpc._bootstrap import bootstrap
from .types import TrajectoryConsequence


bootstrap()
from common import math as td_math  # noqa: E402


class TrajectoryWorldModelEvaluator:
    """Evaluate H-step rollouts with either policy or trajectory terminal action."""

    def __init__(self, agent, horizon: int):
        self.agent = agent
        self.horizon = int(horizon)
        if self.horizon <= 0:
            raise ValueError("World Model horizon must be positive.")

    @torch.no_grad()
    def encode(self, observation: torch.Tensor, task=None) -> torch.Tensor:
        observation = observation.to(self.agent.device, non_blocking=True)
        if observation.ndim == 1:
            observation = observation.unsqueeze(0)
        self.agent.model.eval()
        return self.agent.model.encode(observation, task)

    def _discount(self, task, actions: torch.Tensor):
        discount = self.agent.discount
        if self.agent.cfg.multitask:
            return discount[torch.as_tensor(task, device=actions.device)].reshape(-1, 1)
        return actions.new_tensor(float(discount))

    @torch.no_grad()
    def evaluate(
        self,
        z_t: torch.Tensor,
        actions: torch.Tensor,
        *,
        terminal_action_mode: str,
        task=None,
    ) -> TrajectoryConsequence:
        if actions.ndim != 3:
            raise ValueError(f"actions must be [B,S,A], got {tuple(actions.shape)}.")
        batch, steps, action_dim = actions.shape
        if action_dim != int(self.agent.cfg.action_dim):
            raise ValueError(f"Action dim {action_dim} != configured {self.agent.cfg.action_dim}.")
        expected_steps = self.horizon + (terminal_action_mode == "trajectory")
        if terminal_action_mode not in {"policy", "trajectory"}:
            raise ValueError("terminal_action_mode must be 'policy' or 'trajectory'.")
        if steps != expected_steps:
            raise ValueError(
                f"{terminal_action_mode} mode expects {expected_steps} actions, got {steps}."
            )

        actions = actions.to(self.agent.device).clamp(-1.0, 1.0)
        z = z_t.to(self.agent.device)
        if z.ndim == 1:
            z = z.unsqueeze(0)
        if z.shape[0] == 1 and batch > 1:
            z = z.expand(batch, -1)
        if z.shape != (batch, int(self.agent.cfg.latent_dim)):
            raise ValueError(
                f"Latent shape {tuple(z.shape)} does not match {(batch, int(self.agent.cfg.latent_dim))}."
            )

        model = self.agent.model
        model.eval()
        discount_step = self._discount(task, actions)
        discount = actions.new_ones((batch, 1))
        terminated = actions.new_zeros((batch, 1))
        rewards = []
        total = actions.new_zeros((batch, 1))
        for step in range(self.horizon):
            action = actions[:, step]
            reward = td_math.two_hot_inv(model.reward(z, action, task), self.agent.cfg)
            rewards.append(reward.squeeze(-1))
            total += discount * (1.0 - terminated) * reward
            z = model.next(z, action, task)
            discount = discount * discount_step
            if bool(self.agent.cfg.episodic) and getattr(model, "_termination", None) is not None:
                terminated = torch.clamp(
                    terminated + (model.termination(z, task) > 0.5).to(actions.dtype), max=1.0
                )

        if terminal_action_mode == "trajectory":
            terminal_action = actions[:, self.horizon]
        else:
            terminal_action, _ = model.pi(z, task)
        # Use the full ensemble instead of TD-MPC2's random two-Q subsample. This
        # makes evaluation deterministic and exposes epistemic spread to MPPI.
        terminal_q_all = td_math.two_hot_inv(
            model.Q(z, terminal_action, task, return_type="all"), self.agent.cfg
        )
        terminal_q = terminal_q_all.mean(dim=0)
        terminal_q_std = terminal_q_all.std(dim=0, unbiased=False)
        total += discount * (1.0 - terminated) * terminal_q
        return TrajectoryConsequence(
            reward_sequence=torch.stack(rewards, dim=1).detach(),
            terminal_q=terminal_q.squeeze(-1).detach(),
            terminal_q_std=terminal_q_std.squeeze(-1).detach(),
            total_value=total.squeeze(-1).detach(),
            terminal_latent=z.detach(),
        )

    def evaluate_trajectory_consequence(
        self, z_t: torch.Tensor, actions: torch.Tensor, task=None
    ) -> TrajectoryConsequence:
        return self.evaluate(
            z_t, actions, terminal_action_mode="trajectory", task=task
        )

    def evaluate_policy_terminal(
        self, z_t: torch.Tensor, actions: torch.Tensor, task=None
    ) -> TrajectoryConsequence:
        return self.evaluate(z_t, actions, terminal_action_mode="policy", task=task)

    def evaluate_mppi_candidates(
        self, z_t: torch.Tensor, actions: torch.Tensor, task=None
    ) -> TrajectoryConsequence:
        return self.evaluate_trajectory_consequence(z_t, actions, task=task)


__all__ = ["TrajectoryWorldModelEvaluator"]
