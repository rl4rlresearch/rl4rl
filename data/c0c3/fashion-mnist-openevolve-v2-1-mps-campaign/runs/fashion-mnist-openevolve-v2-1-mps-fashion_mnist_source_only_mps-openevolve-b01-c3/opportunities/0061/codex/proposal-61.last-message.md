MECHANISM: Minibatch-stratified transformation sampling

HYPOTHESIS: Balancing all ten translation/flip transformations within every minibatch will exceed 9,285 correct predictions by reducing augmentation-gradient and BatchNorm-statistic variance without increasing computation.

INTENDED_EDIT: Replace independent per-image transformation sampling with a randomly rotated, near-uniform assignment of the ten training transformations across each batch.

EVIDENCE: The 9,285-correct current design trains on the same ten transformations used at evaluation, but samples them independently; averaging and BatchNorm variants produced regressions or timeouts, motivating this isolated, zero-overhead alignment of each training batch with the evaluation mixture.

<<<<<<< SEARCH
    del step, total_steps
    batch, channels, height, width = images.shape
    padded = F.pad(images, (1, 1, 1, 1), mode="replicate")

    positions = torch.randint(0, 5, (batch,), device=images.device)
    row_offsets = torch.tensor(
        (1, 0, 2, 1, 1), device=images.device
    )[positions].unsqueeze(1)
    col_offsets = torch.tensor(
        (1, 1, 1, 0, 2), device=images.device
    )[positions].unsqueeze(1)

    rows = row_offsets + torch.arange(height, device=images.device).unsqueeze(0)
    row_index = rows[:, None, :, None].expand(
        batch, channels, height, padded.shape[-1]
    )
    images = padded.gather(2, row_index)

    cols = col_offsets + torch.arange(width, device=images.device).unsqueeze(0)
    col_index = cols[:, None, None, :].expand(batch, channels, height, width)
    images = images.gather(3, col_index)

    flip_mask = torch.rand(batch, device=images.device) < 0.5
=======
    del step, total_steps
    batch, channels, height, width = images.shape
    padded = F.pad(images, (1, 1, 1, 1), mode="replicate")

    phase = torch.randint(0, 10, (), device=images.device)
    transformations = (
        torch.arange(batch, device=images.device) + phase
    ).remainder(10)
    positions = transformations.remainder(5)
    flip_mask = transformations >= 5

    row_offsets = torch.tensor(
        (1, 0, 2, 1, 1), device=images.device
    )[positions].unsqueeze(1)
    col_offsets = torch.tensor(
        (1, 1, 1, 0, 2), device=images.device
    )[positions].unsqueeze(1)

    rows = row_offsets + torch.arange(height, device=images.device).unsqueeze(0)
    row_index = rows[:, None, :, None].expand(
        batch, channels, height, padded.shape[-1]
    )
    images = padded.gather(2, row_index)

    cols = col_offsets + torch.arange(width, device=images.device).unsqueeze(0)
    col_index = cols[:, None, None, :].expand(batch, channels, height, width)
    images = images.gather(3, col_index)

>>>>>>> REPLACE