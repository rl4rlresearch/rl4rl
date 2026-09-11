MECHANISM: Sequential final-normalization bias anchoring

HYPOTHESIS: Reproducing the qualified 1495-parameter design and fixing final LayerNorm bias coordinate 1 at zero will yield 1494 parameters while maintaining at least 99% accuracy.

INTENDED_EDIT: Fix the remaining pre-attention LayerNorm scale at one and reconstruct final LayerNorm bias coordinates 0 and 1 as zero, leaving all eight final scales and bias coordinates 2–7 learned.

EVIDENCE: Reference Design 1 achieved 99.83% accuracy at 1495 parameters after fixing final LayerNorm bias coordinate 0; coordinate 1 is the closest untested continuation in that successful zero-initialized bias family, while fixing a final scale failed.

<<<<<<< SEARCH
class SeptupleAnchoredScaleLayerNorm(nn.Module):
    """LayerNorm with seven scales fixed through the following linear-map gauge."""
    def __init__(self, dim: int, eps: float = 1e-5):
        super().__init__()
        self.dim = dim
        self.eps = eps
        self.weight = nn.Parameter(torch.ones(dim - 7))

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        weight = F.pad(self.weight, (0, 7), value=1.0)
        return F.layer_norm(x, (self.dim,), weight, None, self.eps)
=======
class FixedScaleLayerNorm(nn.Module):
    """LayerNorm with all scales fixed through the following linear-map gauge."""
    def __init__(self, dim: int, eps: float = 1e-5):
        super().__init__()
        self.dim = dim
        self.eps = eps

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        return F.layer_norm(x, (self.dim,), None, None, self.eps)


class FirstTwoBiasAnchoredLayerNorm(nn.Module):
    """LayerNorm with final bias coordinates 0 and 1 fixed at zero."""
    def __init__(self, dim: int, eps: float = 1e-5):
        super().__init__()
        self.dim = dim
        self.eps = eps
        self.weight = nn.Parameter(torch.ones(dim))
        self.bias = nn.Parameter(torch.zeros(dim - 2))

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        bias = F.pad(self.bias, (2, 0))
        return F.layer_norm(
            x, (self.dim,), self.weight, bias, self.eps
        )
>>>>>>> REPLACE

<<<<<<< SEARCH
        self.ln1 = SeptupleAnchoredScaleLayerNorm(cfg.d_model)
=======
        self.ln1 = FixedScaleLayerNorm(cfg.d_model)
>>>>>>> REPLACE

<<<<<<< SEARCH
        self.ln_f = nn.LayerNorm(cfg.d_model)
=======
        self.ln_f = FirstTwoBiasAnchoredLayerNorm(cfg.d_model)
>>>>>>> REPLACE