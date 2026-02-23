"""RMSNorm — Root Mean Square Layer Normalization.

Reference: Zhang & Sennrich, 2019 — "Root Mean Square Layer Normalization"
Qwen3 uses pre-RMSNorm (applied before attention/FFN) with no bias.
"""

import torch
import torch.nn as nn


class RMSNorm(nn.Module):
    def __init__(self, hidden_size: int, eps: float = 1e-6):
        super().__init__()
        self.weight = nn.Parameter(torch.ones(hidden_size))
        self.eps = eps

    def _norm(self, x: torch.Tensor) -> torch.Tensor:
        return x * torch.rsqrt(x.pow(2).mean(-1, keepdim=True) + self.eps)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        output = self._norm(x.float()).type_as(x)
        return output * self.weight
