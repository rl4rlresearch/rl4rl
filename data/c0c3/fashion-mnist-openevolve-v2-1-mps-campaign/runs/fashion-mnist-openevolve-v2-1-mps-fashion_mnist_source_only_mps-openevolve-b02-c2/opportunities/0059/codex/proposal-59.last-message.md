MECHANISM: Sample-weighted BatchNorm with fast peak attention

HYPOTHESIS: Restoring hard-maximum attention and weighting BatchNorm updates by actual batch size will exceed 9,322 correct predictions by retaining the 9,320-correct fast architecture while preventing the two 80-example tail batches from disproportionately shifting evaluation statistics.

INTENDED_EDIT: Replace strongest-local-patch attention with verified global-maximum attention and scale BatchNorm momentum on each step to preserve approximately equal running-stat influence per example.

EVIDENCE: Hard-maximum attention reached 9,320 correct in 75.3 seconds, outperforming the current local-patch model’s 9,312 while leaving runtime headroom; the recent BatchNorm hypothesis identified undersized tail batches as a parameter-neutral source of evaluation noise.

<<<<<<< SEARCH
        channel_average = F.adaptive_avg_pool2d(features, 1)
        channel_average = channel_average.flatten(2).transpose(1, 2)
        channel_salient = F.avg_pool2d(features, kernel_size=2, stride=1)
        channel_salient = F.adaptive_max_pool2d(channel_salient, 1)
        channel_salient = channel_salient.flatten(2).transpose(1, 2)
        channel_gate = self.channel_attention(channel_average)
        channel_gate = channel_gate + self.channel_attention(channel_salient)
=======
        channel_average = F.adaptive_avg_pool2d(features, 1)
        channel_average = channel_average.flatten(2).transpose(1, 2)
        channel_maximum = F.adaptive_max_pool2d(features, 1)
        channel_maximum = channel_maximum.flatten(2).transpose(1, 2)
        channel_gate = self.channel_attention(channel_average)
        channel_gate = channel_gate + self.channel_attention(channel_maximum)
>>>>>>> REPLACE

<<<<<<< SEARCH
) -> torch.Tensor:
    del step, total_steps
    paired_images = torch.cat(
        (images, torch.flip(images, dims=(-1,))),
        dim=0,
    )
=======
) -> torch.Tensor:
    del step, total_steps
    batch_fraction = images.shape[0] / BATCH_SIZE
    batch_norm_momentum = 1.0 - (1.0 - 0.1) ** batch_fraction
    for module in model.modules():
        if isinstance(module, nn.BatchNorm2d):
            module.momentum = batch_norm_momentum

    paired_images = torch.cat(
        (images, torch.flip(images, dims=(-1,))),
        dim=0,
    )
>>>>>>> REPLACE