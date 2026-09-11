MECHANISM: Consensus-weighted logit-domain TTA

HYPOTHESIS: Replacing probability averaging with weighted logit averaging will suppress transformation-specific confidence outliers and achieve at least 9,311 correct validation predictions without increasing parameters or runtime.

INTENDED_EDIT: Aggregate the unchanged twelve weighted evaluation views in logit space while preserving view weights and temperature.

EVIDENCE: The normalized 147-unit head reached 9,310 correct, while architectural additions repeatedly timed out and prior TTA weight tuning plateaued; changing only the aggregation rule tests an orthogonal, computation-neutral improvement.

<<<<<<< SEARCH
        ensemble = F.log_softmax(logits, dim=1) + math.log(2.0)
        for view in views[1:]:
            view_logits = self.classifier(self.features(view))
            ensemble = torch.logaddexp(
                ensemble, F.log_softmax(view_logits, dim=1)
            )
        for view_index, view in enumerate(views):
            flipped_logits = self.classifier(self.features(view.flip(-1)))
            flipped_log_probs = F.log_softmax(flipped_logits, dim=1)
            if view_index == 0:
                flipped_log_probs = flipped_log_probs + math.log(2.0)
            ensemble = torch.logaddexp(ensemble, flipped_log_probs)
        return (ensemble - math.log(12.0)) / 0.912
=======
        ensemble = logits * 2.0
        for view in views[1:]:
            view_logits = self.classifier(self.features(view))
            ensemble = ensemble + view_logits
        for view_index, view in enumerate(views):
            flipped_logits = self.classifier(self.features(view.flip(-1)))
            if view_index == 0:
                flipped_logits = flipped_logits * 2.0
            ensemble = ensemble + flipped_logits
        return ensemble / (12.0 * 0.912)
>>>>>>> REPLACE