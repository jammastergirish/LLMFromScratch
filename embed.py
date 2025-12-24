import torch
import torch.nn as nn
from jaxtyping import Float, Int
from torch import Tensor


class EmbedWithoutTorch(nn.Module):
    def __init__(self, cfg):
        super().__init__()
        self.cfg = cfg
        # W_E: [d_vocab, d_model] - embedding matrix
        self.W_E = nn.Parameter(torch.empty((cfg.d_vocab, cfg.d_model)))
        nn.init.normal_(self.W_E, std=self.cfg.init_range)

    def forward(
        self, tokens: Int[Tensor, "batch position"]
    ) -> Float[Tensor, "batch position d_model"]:
        # tokens: [batch, position] - token IDs
        # W_E: [d_vocab, d_model]
        # W_E[tokens]: [batch, position, d_model] - indexed embeddings
        return self.W_E[tokens]


class EmbedWithTorch(nn.Module):
    def __init__(self, cfg):
        super().__init__()
        self.cfg = cfg
        # embedding.weight: [d_vocab, d_model]
        self.embedding = nn.Embedding(cfg.d_vocab, cfg.d_model)
        nn.init.normal_(self.embedding.weight, std=self.cfg.init_range)

    def forward(
        self, tokens: Int[Tensor, "batch position"]
    ) -> Float[Tensor, "batch position d_model"]:
        # tokens: [batch, position] - token IDs
        # embedding(tokens): [batch, position, d_model]
        return self.embedding(tokens)
