"""Student world model.

Students may replace this residual MLP with a GRU or another dynamics model,
but the public interface must stay the same.
"""

from __future__ import annotations

import torch
from torch import nn


class StudentWorldModel(nn.Module):
    def __init__(
        self,
        obs_dim: int = 4,
        act_dim: int = 1,
        hidden_dim: int = 128,
        num_layers: int = 2,
        use_gru: bool = True,
        delta_limit: float = 3.0,
    ):
        super().__init__()
        self.use_gru = bool(use_gru)
        self.delta_limit = float(delta_limit)

        in_dim = obs_dim + act_dim

        layers: list[nn.Module] = []
        cur_dim = in_dim
        for _ in range(int(num_layers)):
            layers += [
                nn.Linear(cur_dim, hidden_dim),
                nn.SiLU(),
            ]
            cur_dim = hidden_dim

        self.encoder = nn.Sequential(*layers)

        self.gru = nn.GRUCell(hidden_dim, hidden_dim) if self.use_gru else None

        self.head = nn.Linear(hidden_dim, obs_dim)

        # Small linear shortcut from [state, action] to delta.
        # Helps local linear dynamics and early-step accuracy.
        self.skip = nn.Linear(in_dim, obs_dim)
        nn.init.zeros_(self.skip.weight)
        nn.init.zeros_(self.skip.bias)

    def initial_hidden(self, batch_size: int, device: torch.device):
        if not self.use_gru:
            return None
        return torch.zeros(batch_size, self.gru.hidden_size, device=device)

    def forward(self, obs_norm: torch.Tensor, act_norm: torch.Tensor, hidden=None):
        x = torch.cat([obs_norm, act_norm], dim=-1)

        feat = self.encoder(x)

        if self.gru is not None:
            if hidden is None:
                hidden = self.initial_hidden(obs_norm.shape[0], obs_norm.device)
            hidden = self.gru(feat, hidden)
            feat = hidden

        raw_delta = self.head(feat) + self.skip(x)

        delta = self.delta_limit * torch.tanh(raw_delta / self.delta_limit)

        return delta, hidden