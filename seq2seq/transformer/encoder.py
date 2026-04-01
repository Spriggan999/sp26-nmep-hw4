from typing import Optional

import math

import torch
import torch.nn as nn

from .attention import MultiHeadAttention, FeedForwardNN
from seq2seq.data.fr_en import tokenizer


class PositionalEncoding(nn.Module):
    """
    The PositionalEncoding layer will take in an input tensor
    of shape (B, T, C) and will output a tensor of the same
    shape, but with positional encodings added to the input.

    We provide you with the full implementation for this
    homework.

    Based on:
        https://web.archive.org/web/20230315052215/https://pytorch.org/tutorials/beginner/transformer_tutorial.html
    """

    def __init__(self, d_model: int, dropout: float = 0.1, max_len: int = 10_000):
        """
        Initialize the PositionalEncoding layer.
        """
        super().__init__()
        self.dropout = nn.Dropout(p=dropout)

        position = torch.arange(max_len).unsqueeze(1)
        div_term = torch.exp(
            torch.arange(0, d_model, 2) * (-math.log(10000.0) / d_model)
        )
        pe = torch.zeros(max_len, 1, d_model)
        pe[:, 0, 0::2] = torch.sin(position * div_term)
        pe[:, 0, 1::2] = torch.cos(position * div_term)
        self.register_buffer("pe", pe)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        """
        Arguments:
            x: Tensor, shape (B, T, C)
        """
        x = x.transpose(0, 1)
        x = x + self.pe[: x.size(0)]
        x = self.dropout(x)
        return x.transpose(0, 1)


class EncoderLayer(nn.Module):
    def __init__(
        self,
        num_heads: int,
        embedding_dim: int,
        ffn_hidden_dim: int,
        qk_length: int,
        value_length: int,
        dropout: float,
    ):
        """
        Each encoder layer will take in an embedding of
        shape (B, T, C) and will output an encoded representation
        of the same shape.

        The encoder layer will have a Multi-Head Attention layer
        and a Feed-Forward Neural Network layer.

        Remember that for each Multi-Head Attention layer, we
        need create Q, K, and V matrices from the input embedding!
        """
        super().__init__()

        self.num_heads = num_heads
        self.embedding_dim = embedding_dim
        self.ffn_hidden_dim = ffn_hidden_dim
        self.qk_length = qk_length
        self.value_length = value_length

        # Define any layers you'll need in the forward pass
        #raise NotImplementedError("Need to implement vocab initialization.")

        # Learnable Linear layers to create Q, K, and V from x (input/embedding)
        self.weight_q = nn.Linear(self.embedding_dim, self.num_heads * self.qk_length)
        self.weight_k = nn.Linear(self.embedding_dim, self.num_heads * self.qk_length)
        self.weight_v = nn.Linear(self.embedding_dim, self.num_heads * self.value_length)

        # Initialize Multi-Head Attention and the FFNN
        self.mha = MultiHeadAttention(self.num_heads, self.embedding_dim, self.qk_length, self.value_length)
        self.ffnn = FeedForwardNN(self.embedding_dim, self.ffn_hidden_dim)
        self.mha_ln = nn.LayerNorm(normalized_shape = self.embedding_dim)
        self.ffnn_ln = nn.LayerNorm(normalized_shape = self.embedding_dim)

    def forward(
        self, x: torch.Tensor, mask: Optional[torch.Tensor] = None
    ) -> torch.Tensor:
        """
        The forward pass of the EncoderLayer.
        """

        # Create the Q, K, and V from learnable linear layers and embedding/input
        Q = self.weight_q(x)
        K = self.weight_k(x)
        V = self.weight_v(x)

        # Pass Q, K, V, and Mask through MH-Attention
        mha_output = self.mha(Q, K, V, mask)
        mha_ln_output = self.mha_ln(mha_output + x)

        # Pass MH-Attention output through FFNN
        ffnn_output = self.ffnn(mha_ln_output)
        ffnn_ln_output = self.ffnn_ln(ffnn_output + mha_ln_output)

        return ffnn_ln_output
        #raise NotImplementedError("Need to implement forward pass of EncoderLayer.")


class Encoder(nn.Module):
    def __init__(
        self,
        vocab_size: int,
        num_layers: int,
        num_heads: int,
        embedding_dim: int,
        ffn_hidden_dim: int,
        qk_length: int,
        value_length: int,
        max_length: int,
        dropout: float,
    ):
        """
        Remember that the encoder will take in a sequence
        of tokens and will output an encoded representation
        of shape (B, T, C).

        First, we need to create an embedding from the sequence
        of tokens. For this, we need the vocab size.

        Next, we want to create a series of Encoder layers,
        each of which will have a Multi-Head Attention layer
        and a Feed-Forward Neural Network layer. For this, we
        need to specify the number of layers and the number of
        heads.

        Additionally, for every Multi-Head Attention layer, we
        need to know how long each query/key is, and how long
        each value is.
        """
        super().__init__()

        self.vocab_size = vocab_size
        self.num_layers = num_layers
        self.num_heads = num_heads
        self.embedding_dim = embedding_dim
        self.ffn_hidden_dim = ffn_hidden_dim

        self.qk_length = qk_length
        self.value_length = value_length

        self.max_length = max_length
        self.dropout = dropout

        # Define any layers you'll need in the forward pass
        # Hint: You may find `ModuleList`s useful for creating
        # multiple layers from some kind of list comprehension.
        #
        # Recall that the input is just a sequence of tokens,
        # so we'll have to first create some kind of embedding
        # and then use the other layers we've implemented to
        # build out the Transformer encoder.
        #raise NotImplementedError("Need to implement Encoder layers")

        self.embedding = nn.Embedding(self.vocab_size, self.embedding_dim)

        self.pos_enc = PositionalEncoding(self.embedding_dim, self.dropout, self.max_length)

        self.encoder_layers = nn.ModuleList()

        for _ in range(self.num_layers):
            self.encoder_layers.append(EncoderLayer(self.num_heads, self.embedding_dim, self.ffn_hidden_dim, self.qk_length, self.value_length, self.dropout))

    def forward(self, x: torch.Tensor, src_mask: Optional[torch.Tensor] = None) -> torch.Tensor:
        """
        The forward pass of the Encoder.
        """
        #raise NotImplementedError("Need to implement forward pass of Encoder")

        x = x.long()

        embed_output = self.embedding(x)

        encoder_output = self.pos_enc(embed_output)

        for layer in self.encoder_layers:
            encoder_output = layer(encoder_output, src_mask)

        return encoder_output

