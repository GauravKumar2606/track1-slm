import torch.nn as nn

from .attention import CausalSelfAttention


class TransformerBlock(nn.Module):
    """Pre-norm transformer decoder block: attention + feed-forward, both with residuals."""

    def __init__(self, d_model: int, n_heads: int, d_ff: int, context_length: int, dropout: float):
        super().__init__()
        self.ln1 = nn.LayerNorm(d_model)
        self.attn = CausalSelfAttention(d_model, n_heads, context_length, dropout)
        self.ln2 = nn.LayerNorm(d_model)
        self.mlp = nn.Sequential(
            nn.Linear(d_model, d_ff),
            nn.GELU(),
            nn.Linear(d_ff, d_model),
            nn.Dropout(dropout),
        )

    def forward(self, x):
        x = x + self.attn(self.ln1(x))
        x = x + self.mlp(self.ln2(x))
        return x
