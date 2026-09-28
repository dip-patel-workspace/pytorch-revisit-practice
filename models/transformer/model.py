import math
import torch
import torch.nn as nn

# Embedding Class:
class InputEmbedding(nn.Module):

    def __init__(self, d_model, vocab_size):
        super().__init__()
        self.d_model = d_model   # embedding vector shape
        self.vocab_size = vocab_size
        self.embedding = nn.Embedding(num_embeddings=vocab_size, 
                                    embedding_dim=d_model)

    def forward(self,x):
        return self.embedding(x) * math.sqrt(self.d_model)

# Possitional Encoedding:
class PositionalEncoding(nn.Module):

    def __init__(self, d_model: int, seq_len: int, dropout: float) -> None:
        super().__init__()
        self.d_model = d_model
        self.seq_len = seq_len
        self.dropout = nn.Dropout(dropout)

        # Create a matrix of shape (seq_len, d_model)
        pe = torch.zeros(seq_len, d_model)

        # Create position of shape (seq_len, 1)
        position = torch.arange(0, seq_len, dtype=torch.float).unsqueeze(1)

        # Create frequency terms
        div_term = torch.exp(
            torch.arange(0, d_model, 2).float()
            * (-math.log(10000.0) / d_model)
        )

        # Even dimensions → sin
        pe[:, 0::2] = torch.sin(position * div_term)

        # Odd dimensions → cos
        pe[:, 1::2] = torch.cos(position * div_term)

        # Shape: (1, seq_len, d_model)
        pe = pe.unsqueeze(0)

        self.register_buffer("pe", pe)  # please do not learn it

    def forward(self, x):
        x = x + self.pe[:, :x.shape[1], :]
        return self.dropout(x)

# class LayerNormalization(nn.Module):

#     def __init__(self, eps: float = 10**-6) -> None:
#         super().__init__()
#         self.eps = eps
#         # Learnable parameters
#         self.alpha = nn.Parameter(torch.ones(1))
#         self.bias = nn.Parameter(torch.zeros(1))

#     def forward(self, x):
#         mean = x.mean(dim=-1, keepdim=True)
#         std = x.std(dim=-1, keepdim=True)
#         return self.alpha * (x - mean) / (std + self.eps) + self.bias

# Layer Normalisation:
class LayerNormalization(nn.Module):

    def __init__(self, eps: float = 10**-6) -> None:
        super().__init__()
        self.eps = eps
        self.alpha = nn.Parameter(torch.ones(1))
        self.bias = nn.Parameter(torch.zeros(1))

    def forward(self, x):
        mean = x.mean(dim=-1, keepdim=True)
        std = x.std(dim=-1, keepdim=True, unbiased=False)
        return self.alpha * (x - mean) / (std + self.eps) + self.bias


# Feed Forward Network (FFN):
class FeedForwardBlock(nn.Module):

    def __init__(self, d_model: int, d_ff: int, dropout: float) -> None:
        super().__init__()

        self.linear_1 = nn.Linear(d_model, d_ff)
        self.dropout = nn.Dropout(dropout)
        self.linear_2 = nn.Linear(d_ff, d_model)

    def forward(self, x):
        return self.linear_2(
            self.dropout(
                torch.relu(
                    self.linear_1(x)
                )
            )
        )
