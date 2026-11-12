"""Llama 3.2 3B causal grouped-query attention with pre-projected Q/K/V.

RoPE is not applied here; inputs are assumed to be already projected and
rotated. The additive causal mask follows the 1B attention benchmark.
"""

import torch
import torch.nn as nn


class Model(nn.Module):
    def __init__(self):
        super().__init__()

    def forward(
        self, Q: torch.Tensor, K: torch.Tensor, V: torch.Tensor
    ) -> torch.Tensor:
        rows = torch.arange(Q.shape[-2], device=Q.device)
        cols = torch.arange(K.shape[-2], device=K.device)
        allowed = rows[:, None] >= cols[None, :]
        mask = allowed.to(dtype=Q.dtype).log()
        return torch.nn.functional.scaled_dot_product_attention(
            Q, K, V, attn_mask=mask, is_causal=False, enable_gqa=True
        )


batch_size = 4
n_ctx = 512
num_heads = 24
num_kv_heads = 8
d_head = 128


def get_inputs():
    Q = torch.rand(batch_size, num_heads, n_ctx, d_head)
    K = torch.rand(batch_size, num_kv_heads, n_ctx, d_head)
    V = torch.rand(batch_size, num_kv_heads, n_ctx, d_head)
    return [Q, K, V]


def get_init_inputs():
    return []
