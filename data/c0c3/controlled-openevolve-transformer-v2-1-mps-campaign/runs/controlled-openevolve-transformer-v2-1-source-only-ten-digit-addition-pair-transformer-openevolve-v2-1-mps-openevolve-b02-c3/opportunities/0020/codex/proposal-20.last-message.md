MECHANISM: Gauge-fixed relative-distance attention routing

HYPOTHESIS: Replacing the seven-dimensional absolute-position lookup with a fixed sinusoidal code and learned per-head relative-distance attention biases will reduce the qualified 1,456-parameter architecture to 1,340 parameters while retaining at least 99% accuracy, because addition’s reusable positional routing can be learned by relative offsets rather than independent vectors at every position.

INTENDED_EDIT: Use the qualified five-coefficient pre-attention LayerNorm, replace the 161-parameter positional embedding with a one-parameter-scaled sinusoidal encoding, and add 44 learned relative-distance attention biases with the softmax-invariant zero-distance coefficient fixed to zero.

EVIDENCE: The 1,456-parameter design achieved 99.91% accuracy, while reducing feed-forward width failed sharply; all qualified designs still assume a full 23-by-7 learned positional table. This patch preserves the verified nonlinear and lexical capacities while directly challenging that shared positional-representation assumption.

<<<<<<< SEARCH
    def logits(self, x: torch.Tensor) -> torch.Tensor:
        weight = self.projection_weight()
        latent = F.linear(x, weight.transpose(0, 1))
        return F.linear(latent, self.code.weight)


class CausalSelfAttention(nn.Module):
=======
    def logits(self, x: torch.Tensor) -> torch.Tensor:
        weight = self.projection_weight()
        latent = F.linear(x, weight.transpose(0, 1))
        return F.linear(latent, self.code.weight)


class GaugeFixedLayerNorm(nn.Module):
    """LayerNorm retaining five learned constant-shift directions."""

    def __init__(self, normalized_shape: int):
        super().__init__()
        if normalized_shape < 4:
            raise ValueError("normalized_shape must be at least four")

        self.norm = nn.LayerNorm(normalized_shape, bias=False)
        self.bias_coeff = nn.Parameter(torch.zeros(normalized_shape - 3))

        basis = torch.zeros(normalized_shape, normalized_shape - 3)
        for col in range(normalized_shape - 3):
            scale = math.sqrt((col + 1) * (col + 2))
            basis[: col + 1, col] = 1.0 / scale
            basis[col + 1, col] = -(col + 1) / scale
        self.register_buffer("basis", basis, persistent=False)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        return self.norm(x) + self.bias_coeff @ self.basis.transpose(0, 1)


class CausalSelfAttention(nn.Module):
>>>>>>> REPLACE

<<<<<<< SEARCH
        self.qkv = nn.Linear(d_model, 3 * d_model, bias=False)
        self.q_bias = nn.Parameter(torch.zeros(d_model))
        self.proj = QuotientOutputLinear(d_model, d_model)
        self.attn_drop = nn.Dropout(dropout)
=======
        self.qkv = nn.Linear(d_model, 3 * d_model, bias=False)
        self.q_bias = nn.Parameter(torch.zeros(d_model))
        self.proj = QuotientOutputLinear(d_model, d_model)

        # Each head learns routing by causal relative distance. Distance zero
        # is fixed because a per-head common bias cancels inside softmax.
        self.relative_bias = nn.Parameter(torch.zeros(n_head, max_seq_len - 1))

        self.attn_drop = nn.Dropout(dropout)
>>>>>>> REPLACE

<<<<<<< SEARCH
        att = (q @ k.transpose(-2, -1)) / math.sqrt(self.head_dim)
        causal = self.mask[:seqlen, :seqlen]
        att = att.masked_fill(~causal, float("-inf"))
=======
        att = (q @ k.transpose(-2, -1)) / math.sqrt(self.head_dim)

        positions = torch.arange(seqlen, device=x.device)
        distance = positions[:, None] - positions[None, :]
        relative_bias = torch.cat(
            (
                self.relative_bias.new_zeros(self.n_head, 1),
                self.relative_bias[:, : seqlen - 1],
            ),
            dim=1,
        )
        att = att + relative_bias[:, distance.clamp_min(0)].unsqueeze(0)

        causal = self.mask[:seqlen, :seqlen]
        att = att.masked_fill(~causal, float("-inf"))
>>>>>>> REPLACE

<<<<<<< SEARCH
        self.ln1 = nn.LayerNorm(cfg.d_model)
        self.attn = CausalSelfAttention(cfg.d_model, cfg.n_head, cfg.dropout, cfg.max_seq_len)
=======
        self.ln1 = GaugeFixedLayerNorm(cfg.d_model)
        self.attn = CausalSelfAttention(cfg.d_model, cfg.n_head, cfg.dropout, cfg.max_seq_len)
>>>>>>> REPLACE

<<<<<<< SEARCH
        self.token_emb = FactorizedTokenEmbedding(
            cfg.vocab_size, cfg.d_model, cfg.d_model - 1
        )
        self.pos_emb = QuotientPositionEmbedding(cfg.max_seq_len, cfg.d_model)
        self.drop = nn.Dropout(cfg.dropout)
=======
        self.token_emb = FactorizedTokenEmbedding(
            cfg.vocab_size, cfg.d_model, cfg.d_model - 1
        )

        positions = torch.arange(cfg.max_seq_len, dtype=torch.float32).unsqueeze(1)
        frequencies = torch.exp(
            -math.log(10000.0)
            * torch.arange(0, cfg.d_model, 2, dtype=torch.float32)
            / cfg.d_model
        )
        angles = positions * frequencies.unsqueeze(0)
        pos_encoding = torch.zeros(cfg.max_seq_len, cfg.d_model)
        pos_encoding[:, 0::2] = torch.sin(angles)
        odd_features = pos_encoding[:, 1::2].shape[1]
        pos_encoding[:, 1::2] = torch.cos(angles[:, :odd_features])
        pos_encoding = pos_encoding - pos_encoding.mean(dim=-1, keepdim=True)
        self.register_buffer("pos_encoding", pos_encoding, persistent=False)
        self.pos_scale = nn.Parameter(torch.tensor(0.02))

        self.drop = nn.Dropout(cfg.dropout)
>>>>>>> REPLACE

<<<<<<< SEARCH
        pos = torch.arange(0, seqlen, device=idx.device).unsqueeze(0)
        x = self.token_emb(idx) + self.pos_emb(pos)
        x = self.drop(x)
=======
        x = self.token_emb(idx)
        x = x + self.pos_scale * self.pos_encoding[:seqlen].unsqueeze(0)
        x = self.drop(x)
>>>>>>> REPLACE