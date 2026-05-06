import logging
import torch
import torch.nn as nn
from torch.nn.functional import log_softmax
import copy
import math

from config import NUMBER_OF_LAYERS, DIM_MODEL, DIM_FEEDFORWARD, NUMBER_OF_ATTENTION_HEAD, DROP_OUT


class EncoderDecoder(nn.Module):
    def __init__(self, encoder, decoder, src_embed, tgt_embed, generator):
        super().__init__()
        self.encoder = encoder
        self.decoder = decoder
        self.src_embed = src_embed
        self.tgt_embed = tgt_embed
        self.generator = generator

    def forward(self, src, tgt, src_mask, tgt_mask):
        return self.decode(self.encode(src, src_mask), src_mask, tgt, tgt_mask)

    def encode(self, src, src_mask):
        return self.encoder(self.src_embed(src), src_mask)

    def decode(self, memory, src_mask, tgt, tgt_mask):
        return self.decoder(self.tgt_embed(tgt), memory, src_mask, tgt_mask)


class Generator(nn.Module):
    """Final linear projection + log-softmax.

    Returns log-probabilities so it pairs with KLDivLoss for label-smoothed
    training. Callers expecting raw logits must not use this class.
    """

    def __init__(self, d_model, vocab):
        super().__init__()
        self.proj = nn.Linear(d_model, vocab)

    def forward(self, x):
        return log_softmax(self.proj(x), dim=-1)


def clones(module, N):
    """Deep-copy module N times into a ModuleList (independent weights)."""
    return nn.ModuleList([copy.deepcopy(module) for _ in range(N)])


class LayerNorm(nn.Module):
    def __init__(self, features, eps=1e-6):
        super().__init__()
        self.a_2 = nn.Parameter(torch.ones(features))
        self.b_2 = nn.Parameter(torch.zeros(features))
        self.eps = eps

    def forward(self, x):
        mean = x.mean(-1, keepdim=True)
        # Standard formula: divide by sqrt(var + eps), not (std + eps).
        var = x.var(-1, keepdim=True, unbiased=False)
        return self.a_2 * (x - mean) / torch.sqrt(var + self.eps) + self.b_2


class Encoder(nn.Module):
    def __init__(self, layer, N):
        super().__init__()
        self.layers = clones(layer, N)
        self.norm = LayerNorm(layer.size)

    def forward(self, x, mask):
        for layer in self.layers:
            x = layer(x, mask)
        return self.norm(x)


class SublayerConnection(nn.Module):
    """Pre-norm residual: y = x + dropout(sublayer(norm(x))).

    Deviates from Vaswani et al. 2017, which applies LayerNorm AFTER the
    residual add (post-norm). Pre-norm is more stable and is now standard,
    but requires an extra LayerNorm at the Encoder/Decoder output.
    """

    def __init__(self, size, dropout):
        super().__init__()
        self.norm = LayerNorm(size)
        self.dropout = nn.Dropout(dropout)

    def forward(self, x, sublayer):
        return x + self.dropout(sublayer(self.norm(x)))


class EncoderLayer(nn.Module):
    def __init__(self, size, self_attn, feed_forward, dropout):
        super().__init__()
        self.self_attn = self_attn
        self.feed_forward = feed_forward
        self.sublayer = clones(SublayerConnection(size, dropout), 2)
        self.size = size

    def forward(self, x, mask):
        x = self.sublayer[0](x, lambda x: self.self_attn(x, x, x, mask))
        return self.sublayer[1](x, self.feed_forward)


class Decoder(nn.Module):
    def __init__(self, layer, N):
        super().__init__()
        self.layers = clones(layer, N)
        self.norm = LayerNorm(layer.size)

    def forward(self, x, memory, src_mask, tgt_mask):
        for layer in self.layers:
            x = layer(x, memory, src_mask, tgt_mask)
        return self.norm(x)


class DecoderLayer(nn.Module):
    def __init__(self, size, self_attn, src_attn, feed_forward, dropout):
        super().__init__()
        self.size = size
        self.self_attn = self_attn
        self.src_attn = src_attn
        self.feed_forward = feed_forward
        self.sublayer = clones(SublayerConnection(size, dropout), 3)

    def forward(self, x, memory, src_mask, tgt_mask):
        m = memory
        x = self.sublayer[0](x, lambda x: self.self_attn(x, x, x, tgt_mask))
        x = self.sublayer[1](x, lambda x: self.src_attn(x, m, m, src_mask))
        return self.sublayer[2](x, self.feed_forward)


def subsequent_mask(size):
    """Returns a (1, size, size) bool mask where True = can attend.

    Used by decoder self-attention to prevent attending to future positions.
    Returned tensor is on CPU; caller must move to the correct device.
    """
    return ~torch.triu(torch.ones(1, size, size, dtype=torch.bool), diagonal=1)


def attention(query, key, value, mask=None, dropout=None):
    """Scaled dot-product attention (Vaswani et al. 2017, eq. 1).

    Args:
        query, key, value: (..., seq, d_k) tensors.
        mask: positions where mask == 0 are filled with -1e9 before softmax.
        dropout: optional nn.Dropout applied to attention probabilities.

    Returns:
        (context, attn_weights) where context is (..., seq, d_k).
    """
    d_k = query.size(-1)
    scores = torch.matmul(query, key.transpose(-2, -1)) / math.sqrt(d_k)
    if mask is not None:
        scores = scores.masked_fill(mask == 0, float("-inf"))
    p_attn = scores.softmax(dim=-1)
    if dropout is not None:
        p_attn = dropout(p_attn)
    return torch.matmul(p_attn, value), p_attn


class MultiHeadedAttention(nn.Module):
    def __init__(self, h, d_model, dropout):
        super().__init__()
        assert d_model % h == 0
        self.d_k = d_model // h
        self.h = h
        self.linears = clones(nn.Linear(d_model, d_model), 4)
        self.dropout = nn.Dropout(p=dropout)

    def forward(self, query, key, value, mask=None):
        if mask is not None:
            mask = mask.unsqueeze(1)
        nbatches = query.size(0)

        # 1) Linear projections: d_model => h x d_k
        query, key, value = [
            lin(x).view(nbatches, -1, self.h, self.d_k).transpose(1, 2)
            for lin, x in zip(self.linears, (query, key, value))
        ]

        # 2) Attention over all heads in parallel
        x, _ = attention(query, key, value, mask=mask, dropout=self.dropout)

        # 3) Concatenate heads and project
        x = x.transpose(1, 2).contiguous().view(nbatches, -1, self.h * self.d_k)
        return self.linears[-1](x)


class PositionwiseFeedForward(nn.Module):
    def __init__(self, d_model, d_ff, dropout):
        super().__init__()
        self.w_1 = nn.Linear(d_model, d_ff)
        self.w_2 = nn.Linear(d_ff, d_model)
        self.dropout = nn.Dropout(dropout)

    def forward(self, x):
        return self.w_2(self.dropout(self.w_1(x).relu()))


class Embeddings(nn.Module):
    def __init__(self, d_model, vocab):
        super().__init__()
        self.lut = nn.Embedding(vocab, d_model)
        self.d_model = d_model

    def forward(self, x):
        return self.lut(x) * math.sqrt(self.d_model)


class PositionalEncoding(nn.Module):
    def __init__(self, d_model, dropout, max_len=5000):
        super().__init__()
        self.dropout = nn.Dropout(p=dropout)

        pe = torch.zeros(max_len, d_model)
        # Explicit float32 to avoid int64 × float promotion ambiguity.
        position = torch.arange(0, max_len, dtype=torch.float32).unsqueeze(1)
        div_term = torch.exp(
            torch.arange(0, d_model, 2) * -(math.log(10000.0) / d_model)
        )
        pe[:, 0::2] = torch.sin(position * div_term)
        pe[:, 1::2] = torch.cos(position * div_term)
        pe = pe.unsqueeze(0)
        self.register_buffer("pe", pe)

    def forward(self, x):
        assert x.size(1) <= self.pe.size(1), (
            f"sequence length {x.size(1)} exceeds PositionalEncoding "
            f"max_len {self.pe.size(1)}"
        )
        x = x + self.pe[:, : x.size(1)]
        return self.dropout(x)


def make_model(
    src_vocab,
    tgt_vocab,
    N=NUMBER_OF_LAYERS,
    d_model=DIM_MODEL,
    d_ff=DIM_FEEDFORWARD,
    h=NUMBER_OF_ATTENTION_HEAD,
    dropout=DROP_OUT,
):
    """Assemble an Encoder-Decoder Transformer and Xavier-initialise weights.

    Args:
        src_vocab, tgt_vocab: vocabulary sizes (including special tokens).
        N: number of layers in both encoder and decoder.
        d_model: model/embedding dimension; must be divisible by h.
        d_ff: inner dimension of the position-wise feed-forward sublayer.
        h: number of attention heads.
        dropout: applied to sublayer outputs, FFN activations, attention
            probabilities, and positional encodings.

    Returns:
        Initialised EncoderDecoder. Embeddings and output projection are NOT
        weight-tied (deviation from section 3.4 of the paper).
    """
    c = copy.deepcopy
    attn = MultiHeadedAttention(h, d_model, dropout)
    ff = PositionwiseFeedForward(d_model, d_ff, dropout)
    position = PositionalEncoding(d_model, dropout)
    model = EncoderDecoder(
        Encoder(EncoderLayer(d_model, c(attn), c(ff), dropout), N),
        Decoder(DecoderLayer(d_model, c(attn), c(attn), c(ff), dropout), N),
        nn.Sequential(Embeddings(d_model, src_vocab), c(position)),
        nn.Sequential(Embeddings(d_model, tgt_vocab), c(position)),
        Generator(d_model, tgt_vocab),
    )

    for p in model.parameters():
        if p.dim() > 1:
            nn.init.xavier_uniform_(p)
    total_params = sum(p.numel() for p in model.parameters())
    logging.info(f"Model parameter count: {total_params:,}")
    return model
