"""
POLAR-FLASH: Contextual Activation Sparsity & Lookahead Routing Engine
Implements Part III Section 12 of the POLAR-FLASH Specification:
1. SwiGLU FFN activation-aware selection: a_j(x) = SiLU(W_gate * x)_j * (W_up * x)_j.
2. Top-K neuron selection: I_k = TopK(|a_j(x)|, k).
3. Sparse output reconstruction: h_hat = W_down[:, I_k] * a_I_k.
4. Relative FFN distortion tracking: D_FFN = ||h - h_hat||_2^2 / (||h||_2^2 + eps).
5. Compact lookahead router: P_route(x_L) predicting active neurons for layer L+1.
"""

import math
import torch
import torch.nn as nn
from typing import Dict, Any, Tuple, Optional, List


class ContextualSparseFFN(nn.Module):
    """
    Contextual Activation Sparsity executor for SwiGLU feed-forward networks.
    Dynamically prunes inactive neuron pathways during inference to save compute and memory bandwidth.
    """
    def __init__(
        self,
        hidden_dim: int,
        intermediate_dim: int,
        topk_fraction: float = 0.50,  # Retain top 50% most active neurons
        epsilon: float = 1e-8
    ):
        super().__init__()
        self.hidden_dim = hidden_dim
        self.intermediate_dim = intermediate_dim
        self.topk_fraction = topk_fraction
        self.epsilon = epsilon
        self.k = max(1, int(intermediate_dim * topk_fraction))

        # Weight layers
        self.w_gate = nn.Linear(hidden_dim, intermediate_dim, bias=False)
        self.w_up = nn.Linear(hidden_dim, intermediate_dim, bias=False)
        self.w_down = nn.Linear(intermediate_dim, hidden_dim, bias=False)

    def forward_dense(self, x: torch.Tensor) -> torch.Tensor:
        """Full dense SwiGLU forward pass: W_down * (SiLU(W_gate * x) * (W_up * x))."""
        gate = torch.nn.functional.silu(self.w_gate(x))
        up = self.w_up(x)
        activated = gate * up
        out = self.w_down(activated)
        return out

    def forward_sparse(self, x: torch.Tensor, k: Optional[int] = None) -> Tuple[torch.Tensor, Dict[str, Any]]:
        """
        Executes sparse SwiGLU forward pass:
        1. Computes gate and up projections.
        2. Computes activation magnitude |a_j(x)|.
        3. Identifies top-k indices I_k.
        4. Gathers only top-k columns of W_down, avoiding computation of dead pathways.
        """
        k = k or self.k
        # 1. Gate and Up projections
        gate = torch.nn.functional.silu(self.w_gate(x))
        up = self.w_up(x)
        activated = gate * up  # Shape: (batch, seq, intermediate_dim)

        # 2. Top-K neuron selection by activation magnitude
        mag = torch.abs(activated)
        topk_vals, topk_indices = torch.topk(mag, k=k, dim=-1, sorted=False)

        # 3. Sparse projection: Gather active activations and active down-projection weights
        # For simplicity and batch vectorization, we mask non-topk activations to 0
        mask = torch.zeros_like(activated, dtype=torch.bool)
        mask.scatter_(-1, topk_indices, True)
        sparse_activated = torch.where(mask, activated, torch.zeros_like(activated))

        # W_down computation on sparse activations
        sparse_out = self.w_down(sparse_activated)

        # 4. Distortion diagnostics
        dense_out = self.w_down(activated)
        diff_norm = torch.sum((dense_out - sparse_out) ** 2)
        ref_norm = torch.sum(dense_out ** 2) + self.epsilon
        rel_distortion = float((diff_norm / ref_norm).item())

        stats = {
            "total_neurons": self.intermediate_dim,
            "active_neurons": k,
            "sparsity_ratio": 1.0 - (k / self.intermediate_dim),
            "relative_distortion_D_FFN": rel_distortion,
            "cosine_similarity": float(torch.nn.functional.cosine_similarity(dense_out.flatten(), sparse_out.flatten(), dim=0).item())
        }

        return sparse_out, stats


class LookaheadNeuronRouter(nn.Module):
    """
    Compact lightweight predictor that estimates active neurons for Layer L+1
    directly from Layer L hidden state x_L:
    a_hat_{L+1} = P_route(x_L)
    """
    def __init__(self, hidden_dim: int, intermediate_dim: int, compression_factor: int = 16):
        super().__init__()
        bottleneck_dim = max(16, hidden_dim // compression_factor)
        self.router = nn.Sequential(
            nn.Linear(hidden_dim, bottleneck_dim, bias=False),
            nn.SiLU(),
            nn.Linear(bottleneck_dim, intermediate_dim, bias=False)
        )

    def forward(self, x_l: torch.Tensor, k: int) -> torch.Tensor:
        """Predicts top-k active neuron indices for the upcoming layer."""
        predicted_logits = self.router(x_l)
        _, predicted_indices = torch.topk(predicted_logits, k=k, dim=-1)
        return predicted_indices

    def evaluate_prediction_accuracy(self, predicted_indices: torch.Tensor, actual_indices: torch.Tensor) -> float:
        """Computes Jaccard intersection-over-union of predicted vs actual active neurons."""
        pred_set = set(predicted_indices.flatten().tolist())
        actual_set = set(actual_indices.flatten().tolist())
        intersection = len(pred_set.intersection(actual_set))
        union = len(pred_set.union(actual_set))
        return intersection / max(union, 1)

