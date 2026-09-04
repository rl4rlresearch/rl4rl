MECHANISM: Stronger high-disparity margin-adaptive flip fusion

HYPOTHESIS: A 0.0275 disagreement-gated adjustment will retain 9,331 correct predictions while reducing validation cross-entropy below the best qualified result of 0.1962260711669922.

INTENDED_EDIT: Replace fixed flip fusion with the reported 0.0275 bounded adjustment toward the higher-margin view for decisive original/flip disagreements.

EVIDENCE: The reported 0.0275 run retained 9,331 correct and reached 0.1962239959716797 cross-entropy, improving on the qualified 0.025 rule’s 0.1962260711669922; its timeout was associated with training duration rather than degraded validation results.

<<<<<<< SEARCH
    def forward(self, images: torch.Tensor) -> torch.Tensor:
        logits = self._forward_once(images)
        if not self.training:
            flipped_logits = self._forward_once(torch.flip(images, dims=(-1,)))
            logits = 1.184 * (
                0.4914921875 * logits + 0.5085078125 * flipped_logits
            )
        return logits
=======
    def forward(self, images: torch.Tensor) -> torch.Tensor:
        logits = self._forward_once(images)
        if not self.training:
            flipped_logits = self._forward_once(torch.flip(images, dims=(-1,)))

            original_top2 = logits.topk(2, dim=1).values
            flipped_top2 = flipped_logits.topk(2, dim=1).values
            original_margin = original_top2[:, 0] - original_top2[:, 1]
            flipped_margin = flipped_top2[:, 0] - flipped_top2[:, 1]
            margin_difference = flipped_margin - original_margin

            disagreement = logits.argmax(dim=1) != flipped_logits.argmax(dim=1)
            decisive = disagreement & (margin_difference.abs() > 0.5)
            adjustment = (
                0.0275
                * torch.tanh(0.5 * margin_difference)
                * decisive.to(logits.dtype)
            )
            flipped_weight = 0.5085009765625 + adjustment
            logits = 1.184 * (
                (1.0 - flipped_weight[:, None]) * logits
                + flipped_weight[:, None] * flipped_logits
            )
        return logits
>>>>>>> REPLACE