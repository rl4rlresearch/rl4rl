MECHANISM: Conservative diagonal-view shrinkage

HYPOTHESIS: A diagonal weight of 0.70 will retain the 9,192 correct predictions achieved at 0.75 while lowering cross-entropy by moving toward the better-calibrated but less accurate 0.50 ensemble.

INTENDED_EDIT: Replace the current CNN with the 249,260-parameter residual design and use a full 3×3 translation-and-flip ensemble with diagonal views weighted at 0.70.

EVIDENCE: Diagonal weights of 0.50, 0.75, and 1.00 produced 9,190, 9,192, and 9,191 correct respectively, while lower weights reduced cross-entropy; a small reduction from 0.75 targets the observed accuracy/calibration boundary.

<<<<<<< SEARCH
class ImageClassifier(nn.Module):
    def __init__(self) -> None:
        super().__init__()
        self.features = nn.Sequential(
            nn.Conv2d(1, 32, kernel_size=3, padding=1, bias=False),
            nn.BatchNorm2d(32),
            nn.ReLU(inplace=True),
            nn.Conv2d(32, 32, kernel_size=3, padding=1, bias=False),
            nn.BatchNorm2d(32),
            nn.ReLU(inplace=True),
            nn.MaxPool2d(2),
            nn.Conv2d(32, 64, kernel_size=3, padding=1, bias=False),
            nn.BatchNorm2d(64),
            nn.ReLU(inplace=True),
            nn.Conv2d(64, 64, kernel_size=3, padding=1, bias=False),
            nn.BatchNorm2d(64),
            nn.ReLU(inplace=True),
            nn.MaxPool2d(2),
        )
        self.classifier = nn.Sequential(
            nn.Flatten(),
            nn.Linear(64 * 7 * 7, 56),
            nn.BatchNorm1d(56),
            nn.ReLU(inplace=True),
            nn.Dropout(p=0.15),
            nn.Linear(56, 10),
        )

    def _forward_once(self, images: torch.Tensor) -> torch.Tensor:
        return self.classifier(self.features(images))

    def forward(self, images: torch.Tensor) -> torch.Tensor:
        logits = self._forward_once(images)
        if self.training:
            return logits
        flipped_logits = self._forward_once(images.flip(-1))
        return 0.5 * (logits + flipped_logits)
=======
class ResidualBlock(nn.Module):
    def __init__(self, in_channels: int, out_channels: int) -> None:
        super().__init__()
        self.conv1 = nn.Conv2d(
            in_channels, out_channels, kernel_size=3, padding=1, bias=False
        )
        self.bn1 = nn.BatchNorm2d(out_channels)
        self.conv2 = nn.Conv2d(
            out_channels, out_channels, kernel_size=3, padding=1, bias=False
        )
        self.bn2 = nn.BatchNorm2d(out_channels)
        self.shortcut = nn.Sequential(
            nn.Conv2d(in_channels, out_channels, kernel_size=1, bias=False),
            nn.BatchNorm2d(out_channels),
        )

    def forward(self, inputs: torch.Tensor) -> torch.Tensor:
        residual = self.shortcut(inputs)
        outputs = F.relu(self.bn1(self.conv1(inputs)), inplace=True)
        outputs = self.bn2(self.conv2(outputs))
        return F.relu(outputs + residual, inplace=True)


class ImageClassifier(nn.Module):
    def __init__(self) -> None:
        super().__init__()
        self.features = nn.Sequential(
            ResidualBlock(1, 32),
            nn.MaxPool2d(2),
            ResidualBlock(32, 64),
            nn.MaxPool2d(2),
            ResidualBlock(64, 96),
            nn.MaxPool2d(2),
        )
        self.classifier = nn.Sequential(
            nn.Flatten(),
            nn.Linear(96 * 3 * 3, 42),
            nn.BatchNorm1d(42),
            nn.ReLU(inplace=True),
            nn.Dropout(p=0.15),
            nn.Linear(42, 10),
        )

    def _forward_once(self, images: torch.Tensor) -> torch.Tensor:
        return self.classifier(self.features(images))

    def forward(self, images: torch.Tensor) -> torch.Tensor:
        if self.training:
            return self._forward_once(images)

        _, _, height, width = images.shape
        padded = F.pad(images, (1, 1, 1, 1), mode="replicate")
        logit_sum = None
        for row_offset in range(3):
            for column_offset in range(3):
                view = padded[
                    :,
                    :,
                    row_offset : row_offset + height,
                    column_offset : column_offset + width,
                ]
                is_diagonal = row_offset != 1 and column_offset != 1
                weight = 0.70 if is_diagonal else 1.0
                view_logits = self._forward_once(view)
                flipped_logits = self._forward_once(view.flip(-1))
                weighted_logits = weight * (view_logits + flipped_logits)
                if logit_sum is None:
                    logit_sum = weighted_logits
                else:
                    logit_sum = logit_sum + weighted_logits
        return logit_sum / 15.6
>>>>>>> REPLACE