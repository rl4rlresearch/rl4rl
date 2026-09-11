MECHANISM: Isolated pre-attention LayerNorm common-mode quotient

HYPOTHESIS: Removing only the uniform direction of `ln1.bias` will reduce the current model from 1,620 to 1,619 parameters while retaining at least 99% accuracy, because the retained query and unrestricted projection biases can absorb its effects without the optimization interaction introduced by simultaneously quotienting `attn.proj.bias`.

INTENDED_EDIT: Represent `ln1.bias` in a seven-dimensional zero-sum basis, reconstruct it in the forward pass, and train it using the existing full-coordinate AdamW quotient updates.

EVIDENCE: The current 1,620-parameter design achieved 99.95%, and the qualified design containing this quotient achieved 99.94% at 1,618 parameters. The later combined 1,618-parameter rerun fell to 73.14%, motivating an isolated test that preserves the full attention-projection bias.

<<<<<<< SEARCH
        self.ln1 = nn.LayerNorm(cfg.d_model)
        self.attn = CausalSelfAttention(cfg.d_model, cfg.n_head, cfg.dropout, cfg.max_seq_len)
        self.ln2 = nn.LayerNorm(cfg.d_model)
=======
        self.ln1 = nn.LayerNorm(cfg.d_model)

        # A uniform pre-attention shift is absorbable by the retained query
        # and output-projection biases; key shifts cancel from the softmax.
        self.ln1.bias = nn.Parameter(self.ln1.bias.new_zeros(cfg.d_model - 1))
        ln1_bias_basis = torch.zeros(cfg.d_model, cfg.d_model - 1)
        for col in range(cfg.d_model - 1):
            scale = math.sqrt((col + 1) * (col + 2))
            ln1_bias_basis[: col + 1, col] = 1.0 / scale
            ln1_bias_basis[col + 1, col] = -(col + 1) / scale
        self.register_buffer("ln1_bias_basis", ln1_bias_basis, persistent=False)

        self.attn = CausalSelfAttention(cfg.d_model, cfg.n_head, cfg.dropout, cfg.max_seq_len)
        self.ln2 = nn.LayerNorm(cfg.d_model)
>>>>>>> REPLACE

<<<<<<< SEARCH
    def forward(self, x: torch.Tensor) -> torch.Tensor:
        x = x + self.attn(self.ln1(x))
        ln2_bias = self.ln2_bias_basis @ self.ln2.bias
=======
    def forward(self, x: torch.Tensor) -> torch.Tensor:
        ln1_bias = self.ln1_bias_basis @ self.ln1.bias
        normalized = F.layer_norm(
            x,
            self.ln1.normalized_shape,
            self.ln1.weight,
            ln1_bias,
            self.ln1.eps,
        )
        x = x + self.attn(normalized)

        ln2_bias = self.ln2_bias_basis @ self.ln2.bias
>>>>>>> REPLACE

<<<<<<< SEARCH
        for pair in (
            (blk.mlp.fc2.bias, blk.mlp.bias_basis),
            (blk.ln2.bias, blk.ln2_bias_basis),
        )
=======
        for pair in (
            (blk.mlp.fc2.bias, blk.mlp.bias_basis),
            (blk.ln1.bias, blk.ln1_bias_basis),
            (blk.ln2.bias, blk.ln2_bias_basis),
        )
>>>>>>> REPLACE