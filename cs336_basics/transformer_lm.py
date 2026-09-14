import torch

from cs336_basics.embedding import Embedding
from cs336_basics.linear import Linear
from cs336_basics.rms_norm import RMSNorm
from cs336_basics.transformer import TransformerBlock


class TransformerLM(torch.nn.Module):
    token_embeddings: Embedding
    layers: torch.nn.ModuleList
    ln_final: RMSNorm
    lm_head: Linear

    def __init__(self, vocab_size: int, context_length: int, num_layers: int, d_model: int, num_heads: int, d_ff: int | None = None, eps: float = 1e-5,
                 theta: float | None = None, device: torch.device | None = None, dtype: torch.dtype | None = None):
        super().__init__()
        self.token_embeddings = Embedding(num_embeddings=vocab_size, embedding_dim=d_model, device=device, dtype=dtype)
        self.layers = torch.nn.ModuleList(
            TransformerBlock(d_model, num_heads, d_ff, eps, context_length, theta, device=device, dtype=dtype) for _ in range(num_layers))
        self.ln_final = RMSNorm(d_model, eps, device=device, dtype=dtype)
        self.lm_head = Linear(d_model, vocab_size, device=device, dtype=dtype)
        pass

    def forward(self, x: torch.Tensor) -> torch.Tensor:  # => [FLOPs] 24 bnd²l + 4bn²dl + 2bnd * vocab_size
        y = self.token_embeddings(x)
        for transformer in self.layers:  # => [FLOPs] 24 bnd²l + 4bn²dl
            y = transformer(y)  # => [FLOPs] 24 bnd² + 4bn²d
        y = self.ln_final(y)
        y = self.lm_head(y)  # => [FLOPs] (b, n, d) @ (d, vocab_size) = 2bnd * vocab_size
        return y
