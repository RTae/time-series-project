import os
import random
from collections import defaultdict
from dataclasses import dataclass, field
from pathlib import Path
from typing import Any

import numpy as np
import torch
import torch.nn.functional as F
import torch.optim as optim
from loguru import logger
from torch.optim import AdamW
from torch.utils.data import DataLoader

from src.encoders.eeg_augmentation import smooth_eeg

# -- EEG channel groups --
PRE_FRONTAL = ["FP1", "FPZ", "FP2", "AF3", "AF4"]
FRONTAL = ["F7", "F5", "F3", "F1", "FZ", "F2", "F4", "F6", "F8"]
CENTRAL = ["CZ", "FCZ", "C1", "C2", "C3", "C4", "FC1", "FC2", "FC3", "FC4"]
L_TEMPORAL = ["FT7", "FC5", "T7", "C5", "TP7", "CP5", "P7", "P5"]
R_TEMPORAL = ["FT8", "FC6", "T8", "C6", "TP8", "CP6", "P8", "P6"]
PARIETAL = ["CPZ", "CP1", "CP3", "CP2", "CP4", "PZ", "P1", "P3", "P2", "P4"]
OCCIPITAL = ["POZ", "PO3", "PO5", "PO7", "PO4", "PO6", "PO8", "O1", "O2", "OZ", "CB1", "CB2"]

FREQ_BANDS: dict[str, list[float]] = {
    "delta": [0.5, 4],
    "theta": [4, 8],
    "alpha": [8, 13],
    "beta": [13, 30],
    "gamma": [30, 80],
}

# Resolve project root relative to this file so paths work from any cwd.
_PROJECT_ROOT = Path(__file__).resolve().parent.parent
DEFAULT_DATA_DIR = _PROJECT_ROOT / "data"
DEFAULT_IMG_DIR = DEFAULT_DATA_DIR / "imageNet_images"


def set_seed(seed: int) -> None:
    """Set random seeds for Python, NumPy, and PyTorch for reproducibility."""
    random.seed(seed)
    np.random.seed(seed)
    torch.manual_seed(seed)
    torch.cuda.manual_seed_all(seed)
# ---------------------------------------------------------------------------
# SUPAEEG training config & helpers
# ---------------------------------------------------------------------------


@dataclass
class Config:
    """All runtime hyperparameters for SUPAEEG training."""

    protocol: str = "intra"
    subject: int = 1
    all_subjects: list[int] = field(default_factory=lambda: list(range(1, 11)))
    dataset_dir: str = "data/things_eeg"
    device: str = "cuda"
    epochs: int = 60
    batch_size: int = 512
    eval_every: int = 5
    n_channels: int = 17
    n_timepoints: int = 100
    feature_dim: int = 512
    eeg_feature_dim: int = 1024
    image_input_dim: int = 3200
    image_mid_dim: int = 1024
    dropout: float = 0.3
    n_subjects: int = 10
    n_layers: int = 5
    router_temperature: float = 1.0
    subject_dropout_rate: float = 0.3
    layer_dropout_rate: float = 0.1
    lr: float = 1e-4
    weight_decay: float = 1e-4
    grad_clip: float = 1.0
    stage1_epochs: int = 20
    stage2_lr: float = 5e-5
    mmd_start: float = 0.9
    mmd_end: float = 0.5
    internvit_model: str = "OpenGVLab/InternViT-6B-448px-V1-5"
    internvit_dir: str = "data/things_eeg/image_feature/internvit_multilevel_20_24_28_32_36"
    layer_ids: list[int] = field(default_factory=lambda: [20, 24, 28, 32, 36])
    train_img_dir: str = "data/things_eeg/training_images"
    test_img_dir: str = "data/things_eeg/test_images"
    metadata_path: str = "data/things_eeg/image_metadata.npy"
    data_average: bool = True
    data_average_test: bool = False
    eeg_suffix: str = ""          # "" = 17-ch (sub-XX), "_63" = 63-ch (sub-XX_63)
    eeg_t_start: float = -0.2   # crop start in seconds (stimulus onset)
    eeg_t_end: float = 0.8     # crop end in seconds (matches default 100-point epoch)
    smooth_prob: float = 0.3
    smooth_kernel_size: int = 5
    smooth_sigma: float = 1.0
    early_stop_patience: int = 3
    warmup_epochs: int = 5
    seed: int = 42
    share_encoder_type: str = "linear"   # linear | none | separate | transformer | tokenized_cls | jepa
    eeg_encoder_type: str = "eegproject"
    image_layer_mode: str = "router"
    image_layer_index: int = 0
    temporal_compression: int = 0
    image_feature_path: str = ""
    skip_feature_extraction: bool = False


def train_one_epoch(
    model: Any,
    train_loader: DataLoader,
    optimizer: AdamW,
    internvit_lookup: Any,
    device: torch.device,
    epoch: int,
    config: "Config",
) -> dict[str, float]:
    """Run a single training epoch.

    Args:
        model:            SUPAEEG model (will be set to train mode).
        train_loader:     DataLoader for the training split.
        optimizer:        AdamW optimiser.
        internvit_lookup: InternViTFeatureLookup for retrieving image features.
        device:           Compute device.
        epoch:            Current epoch number (1-indexed).
        config:           Runtime configuration.

    Returns:
        Dict with mean loss components over the epoch.
    """
    from src.trainer.loss import compute_loss  # local import avoids circular deps

    model.train()
    sums: dict[str, float] = {"total": 0.0, "infonce": 0.0, "mmd": 0.0, "mmd_weight": 0.0}
    n_batches = 0
    for batch in train_loader:
        eeg: torch.Tensor = batch["eeg"].to(device)
        subject_ids: torch.Tensor = batch["subject_ids"].to(device)

        # smooth augmentation — training only
        eeg = smooth_eeg(
            eeg,
            kernel_size=config.smooth_kernel_size,
            sigma=config.smooth_sigma,
            p=config.smooth_prob,
        )

        image_layers = internvit_lookup.retrieve_batch(
            batch["image_concepts"], batch["image_files"]
        ).to(device)

        zE, zI = model(eeg, image_layers, subject_ids)

        loss, components = compute_loss(
            zE, zI, model.logit_scale,
            epoch, config.stage1_epochs,
            config.mmd_start, config.mmd_end,
        )
        optimizer.zero_grad()
        loss.backward()
        torch.nn.utils.clip_grad_norm_(model.parameters(), config.grad_clip)
        optimizer.step()

        for k in sums:
            sums[k] += float(components[k])
        n_batches += 1

    n = max(n_batches, 1)
    return {k: v / n for k, v in sums.items()}


def evaluate(
    model: Any,
    test_loader: DataLoader,
    internvit_lookup: Any,
    device: torch.device,
) -> tuple[float, float]:
    """Zero-shot concept retrieval evaluation on the test set.

    Aggregates per-concept EEG embeddings (averaged over repetitions) and
    paired InternViT image embeddings, then computes Top-1 and Top-5 retrieval
    accuracy via the diagonal-retrieval protocol.

    Args:
        model:            SUPAEEG model.
        test_loader:      DataLoader over the test split.
        internvit_lookup: InternViTFeatureLookup instance (test split).
        device:           Compute device.

    Returns:
        Tuple ``(top1, top5)`` accuracy values in [0, 1].
    """
    from src.trainer.metrics import retrieve_all  # local import avoids circular deps

    model.eval()
    concept_embeddings: dict[str, list[torch.Tensor]] = defaultdict(list)
    concept_to_file: dict[str, str] = {}

    with torch.no_grad():
        for batch in test_loader:
            eeg = batch["eeg"].to(device)
            zE = model.embed(eeg)  # (batch, 512), l2-normalised
            for i, (concept, img_file) in enumerate(
                zip(batch["image_concepts"], batch["image_files"])
            ):
                concept_embeddings[concept].append(zE[i].cpu())
                concept_to_file[concept] = img_file

    concept_order = sorted(concept_embeddings.keys())

    eeg_features = torch.cat(
        [
            F.normalize(
                torch.stack(concept_embeddings[c]).mean(dim=0, keepdim=True),
                dim=1,
            )
            for c in concept_order
        ],
        dim=0,
    ).numpy()  # (200, 512)

    # Build image gallery from InternViT lookup
    gallery = internvit_lookup.retrieve_batch(
        concept_order, [concept_to_file[c] for c in concept_order]
    )  # (N_concepts, n_layers, 3200)
    with torch.no_grad():
        image_features = model.encode_image(
            gallery.to(device),
            subject_ids=None,
        ).cpu().numpy()  # (N_concepts, 512)

    top5_count, top1_count, total = retrieve_all(eeg_features, image_features)
    return top1_count / total, top5_count / total


def save_checkpoint(
    model: Any,
    optimizer: AdamW,
    epoch: int,
    top1: float,
    top5: float,
    path: str,
) -> None:
    """Persist model and optimiser state to disk.

    Args:
        model:     SUPAEEG model.
        optimizer: AdamW optimiser.
        epoch:     Current training epoch.
        top1:      Top-1 accuracy at this checkpoint.
        top5:      Top-5 accuracy at this checkpoint.
        path:      File path for the checkpoint (``.pt``).
    """
    os.makedirs(os.path.dirname(os.path.abspath(path)), exist_ok=True)
    torch.save(
        {
            "model": model.state_dict(),
            "optimizer": optimizer.state_dict(),
            "epoch": epoch,
            "top1": top1,
            "top5": top5,
        },
        path,
    )
    logger.info(f"Checkpoint saved | top1={top1:.4f} | path={path}")


def log_results_table(
    results: dict[int, dict[str, float]],
    avg_top1: float,
    avg_top5: float,
    protocol: str,
) -> None:
    """Log per-subject results in tabular format.

    Matches the Table 1 layout from the Shallow Alignment paper.

    Args:
        results:  Mapping of subject_id → {``'top1'``: float, ``'top5'``: float}.
        avg_top1: Average Top-1 accuracy across all subjects.
        avg_top5: Average Top-5 accuracy across all subjects.
        protocol: ``"intra"`` or ``"inter"``.
    """
    logger.info(f"\n{'=' * 60}")
    logger.info(f"Protocol: {protocol.upper()}-SUBJECT")
    logger.info(f"{'Subject':<12} {'Top-1':>8} {'Top-5':>8}")
    logger.info(f"{'-' * 30}")
    for subject_id, r in sorted(results.items()):
        logger.info(
            f"Sub{subject_id:02d}{'':>8} "
            f"{r['top1'] * 100:>7.1f}% "
            f"{r['top5'] * 100:>7.1f}%"
        )
    logger.info(f"{'-' * 30}")
    logger.info(
        f"{'Avg':<12} "
        f"{avg_top1 * 100:>7.1f}% "
        f"{avg_top5 * 100:>7.1f}%"
    )
    logger.info(f"{'=' * 60}\n")


def make_model(
    config: Config,
    device: torch.device,
) -> Any:
    """Instantiate a fresh SUPAEEG model from ``config``.

    Args:
        config: Runtime configuration.
        device: Compute device.

    Returns:
        Initialised SUPAEEG model placed on ``device``.
    """
    from src.models.supaeeg import SUPAEEG  # local import avoids circular deps

    n_layers = len(config.layer_ids)
    if n_layers == 0:
        raise ValueError("config.layer_ids must contain at least one layer")
    if config.n_layers != n_layers:
        logger.warning(
            "config.n_layers (%d) does not match len(config.layer_ids) (%d); "
            "using len(config.layer_ids) for model construction",
            config.n_layers,
            n_layers,
        )

    logger.info("Model share_encoder_type={}", config.share_encoder_type)

    return SUPAEEG(
        n_channels=config.n_channels,
        n_timepoints=config.n_timepoints,
        eeg_feature_dim=config.eeg_feature_dim,
        image_input_dim=config.image_input_dim,
        image_mid_dim=config.image_mid_dim,
        feature_dim=config.feature_dim,
        dropout=config.dropout,
        n_subjects=config.n_subjects,
        n_layers=n_layers,
        router_temperature=config.router_temperature,
        subject_dropout_rate=config.subject_dropout_rate,
        layer_dropout_rate=config.layer_dropout_rate,
        share_encoder_type=config.share_encoder_type,
        eeg_encoder_type=config.eeg_encoder_type,
        image_layer_mode=config.image_layer_mode,
        image_layer_index=config.image_layer_index,
        temporal_compression=config.temporal_compression,
    ).to(device)


def make_scheduler(
    optimizer: AdamW,
    config: "Config",
) -> Any:
    """Build a LR scheduler. Returns a no-op when warmup_epochs == 0.

    When warmup_epochs > 0: LinearLR warmup from stage2_lr → lr, then
    CosineAnnealingLR decay back to stage2_lr over remaining epochs.

    Args:
        optimizer: The AdamW optimiser to schedule.
        config:    Runtime configuration.

    Returns:
        A scheduler with a .step() method.
    """
    from torch.optim.lr_scheduler import ConstantLR, CosineAnnealingLR, LinearLR, SequentialLR

    if config.warmup_epochs <= 0:
        # No-op: keep constant lr throughout training
        return ConstantLR(optimizer, factor=1.0, total_iters=1)

    epochs = int(config.epochs)
    warmup_epochs = int(config.warmup_epochs)
    lr = float(config.lr)
    min_lr = float(config.stage2_lr)

    if epochs <= 0:
        raise ValueError(f"epochs must be > 0, got {epochs}")

    # Allow disabling warmup via warmup_epochs=0.
    if warmup_epochs <= 0:
        return CosineAnnealingLR(
            optimizer,
            T_max=max(epochs, 1),
            eta_min=min_lr,
        )

    if not (0.0 < min_lr <= lr):
        raise ValueError(
            f"stage2_lr must be in (0, lr], got stage2_lr={min_lr} lr={lr}"
        )

    warmup = LinearLR(
        optimizer,
        start_factor=min_lr / lr,
        end_factor=1.0,
        total_iters=warmup_epochs,
    )
    decay = CosineAnnealingLR(
        optimizer,
        T_max=max(epochs - warmup_epochs, 1),
        eta_min=min_lr,
    )
    return SequentialLR(
        optimizer,
        schedulers=[warmup, decay],
        milestones=[warmup_epochs],
    )

def make_optimizer(model: Any, config: Config) -> AdamW:
    """Build an AdamW optimiser from ``config``.

    Args:
        model:  Model whose parameters will be optimised.
        config: Runtime configuration.

    Returns:
        Configured AdamW optimiser.
    """
    return AdamW(
        model.parameters(),
        lr=config.lr,
        weight_decay=config.weight_decay,
    )
