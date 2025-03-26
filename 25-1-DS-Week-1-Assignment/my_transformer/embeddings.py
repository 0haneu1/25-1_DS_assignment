import torch
import torch.nn as nn
import math
from torch import Tensor

class TokenEmbedding(nn.Module):
    def __init__(self, vocab_size: int, d_model: int) -> None:
        super(TokenEmbedding, self).__init__()
        self.embedding = nn.Embedding(vocab_size, d_model)
    
    def forward(self, x: Tensor) -> Tensor:
        return self.embedding(x)

class PositionEmbedding(nn.Module):
    def __init__(self, d_model: int, max_len: int = 5000) -> None:
        super(PositionEmbedding, self).__init__()
        #TODO
        self.embedding = nn.Embedding(max_len, d_model)
    
    def forward(self, x: Tensor) -> Tensor:
        #TODO one line!
        return self.embedding(torch.arange(0, x.size(1), device = x.device).unsqueeze(0).expand(x.size(0), x.size(1)))