"""SSL model builders for benchmarks.

Each model file (simclr.py, dino.py, etc.) exposes:
  - ``build(cfg, ds_config)`` → ``(spt.Module, embed_dim)``
  - ``create_transforms(ds_config)`` → ``(train_transform, val_transform, collate_fn)``

Shared helpers live here.
"""

from __future__ import annotations

import logging
from collections.abc import Mapping

import stable_pretraining as spt
import torch
import torchmetrics
from lightning.pytorch.callbacks import LearningRateMonitor
from stable_pretraining.callbacks.lidar import LiDAR
from stable_pretraining.callbacks.rankme import RankMe
from stable_pretraining.data import transforms
from torch import nn

from benchmarks.models.probe_sweep import (
    SweepLinearProbe,
    build_sweep_metrics,
    expand_grid,
    sweep_ce_loss,
)
from benchmarks.models.vit import create_resnet, create_vit


log = logging.getLogger(__name__)

DEFAULT_EMBED_DIM = 512


# Backbone


def get_embedding_dim(backbone: nn.Module) -> int:
    """Get embedding dimension from a backbone, trying multiple conventions."""
    if hasattr(backbone, "config") and hasattr(backbone.config, "hidden_size"):
        return backbone.config.hidden_size
    for attr in ("num_features", "embed_dim"):
        if hasattr(backbone, attr):
            return getattr(backbone, attr)
    if hasattr(backbone, "fc") and hasattr(backbone.fc, "in_features"):
        return backbone.fc.in_features
    return DEFAULT_EMBED_DIM


def _cfg_value(cfg, key, default=None):
    """Read a config/object attribute without assuming a concrete config type."""
    if isinstance(cfg, Mapping):
        return cfg.get(key, default)
    return getattr(cfg, key, default)


def resolve_backbone_name(backbone_cfg, ds_config=None) -> str:
    """Resolve a backbone config/object into a concrete timm model name."""
    if isinstance(backbone_cfg, str):
        return backbone_cfg

    name = _cfg_value(backbone_cfg, "name")
    if isinstance(name, str):
        if "_patch" in name:
            return name
        patch_size = _cfg_value(backbone_cfg, "patch_size")
        image_size = None
        if ds_config is not None:
            image_size = ds_config.image_size[0]
        if patch_size is not None and image_size is not None:
            return f"{name}_patch{patch_size}_{image_size}"
        return name

    backbone_type = _cfg_value(backbone_cfg, "type")
    size = _cfg_value(backbone_cfg, "size")
    patch_size = _cfg_value(backbone_cfg, "patch_size")
    if backbone_type == "vit" and size and patch_size:
        image_size = 224 if ds_config is None else ds_config.image_size[0]
        return f"vit_{size}_patch{patch_size}_{image_size}"
    if backbone_type == "resnet" and size:
        return f"resnet{size}"

    raise TypeError(f"Unsupported backbone config: {backbone_cfg!r}")


def resolve_backbone_family(backbone_cfg) -> str:
    """Classify a backbone config/name into an architecture family.

    Returns ``"vit"`` or ``"resnet"``. Mirrors the ``"vit" in name`` convention
    used by :func:`benchmarks.models.vit.create_vit`; used to select the
    per-backbone optimizer block and to tag/label runs.
    """
    name = resolve_backbone_name(backbone_cfg)
    backbone_type = _cfg_value(backbone_cfg, "type") if not isinstance(backbone_cfg, str) else None
    if backbone_type == "vit" or "vit" in name:
        return "vit"
    if backbone_type == "resnet" or "resnet" in name:
        return "resnet"
    raise TypeError(f"Cannot determine backbone family for: {backbone_cfg!r}")


def create_backbone(
    backbone_cfg,
    ds_config,
    patch_size: int | None = None,
    img_size: int | tuple[int, int] | None = None,
    drop_path_rate: float = 0.0,
) -> nn.Module:
    """Create a backbone from either a timm model name or a structured config.

    Always builds a 3-channel patch embed: the SSL transform pipeline starts
    with ``transforms.RGB()`` which upcasts grayscale source images to 3
    channels before they reach the model.

    ``patch_size`` and ``img_size`` override the defaults derived from the
    backbone name / ds_config when a dataset needs a non-standard ViT config
    (e.g. small native resolution with a finer patch grid).
    """
    name = resolve_backbone_name(backbone_cfg, ds_config)
    if resolve_backbone_family(backbone_cfg) == "resnet":
        # patch_size / img_size are ViT concepts; ResNets accept any input size
        # natively, so they are ignored here.
        return create_resnet(name, in_chans=3)
    effective_img_size = img_size if img_size is not None else ds_config.image_size
    return create_vit(
        name, img_size=effective_img_size, in_chans=3, patch_size=patch_size,
        drop_path_rate=drop_path_rate,
    )


# Projector


def create_projector(embed_dim: int, hidden_dim: int, output_dim: int) -> nn.Module:
    """Create a 3-layer MLP projection head with BatchNorm."""
    return nn.Sequential(
        nn.Linear(embed_dim, hidden_dim),
        nn.BatchNorm1d(hidden_dim),
        nn.ReLU(inplace=True),
        nn.Linear(hidden_dim, hidden_dim),
        nn.BatchNorm1d(hidden_dim),
        nn.ReLU(inplace=True),
        nn.Linear(hidden_dim, output_dim),
    )


# Optimizer config


def build_optim_config(model_cfg, backbone=None) -> dict:
    """Build optimizer config dict from model config.

    ``backbone`` selects the per-backbone optimizer block: a ResNet backbone
    uses ``resnet_optimizer``, a ViT uses ``vit_optimizer``. The scheduler now
    lives nested under the selected optimizer block. Falls back to
    ``vit_optimizer``/``optimizer`` and a top-level ``scheduler`` for back-compat.
    """
    family = resolve_backbone_family(backbone) if backbone is not None else "vit"
    family_key = f"{family}_optimizer"
    if hasattr(model_cfg, family_key):
        opt_cfg = getattr(model_cfg, family_key)
    elif hasattr(model_cfg, "vit_optimizer"):
        opt_cfg = model_cfg.vit_optimizer
    else:
        opt_cfg = model_cfg.optimizer

    scheduler_src = opt_cfg.scheduler if hasattr(opt_cfg, "scheduler") else model_cfg.scheduler
    scheduler_cfg = {"type": scheduler_src.type}
    if hasattr(model_cfg, "_total_steps"):
        total_steps = int(model_cfg._total_steps)
        scheduler_cfg["total_steps"] = total_steps
        scheduler_cfg["peak_step"] = max(1, int(0.01 * total_steps))

    optim = {
        "optimizer": {
            "type": opt_cfg.type,
            "lr": opt_cfg.lr,
            "weight_decay": opt_cfg.weight_decay,
        },
        "scheduler": scheduler_cfg,
        "interval": "step",
    }
    if hasattr(opt_cfg, "betas"):
        optim["optimizer"]["betas"] = tuple(opt_cfg.betas)
    if hasattr(model_cfg, "_lr_override"):
        optim["optimizer"]["lr"] = model_cfg._lr_override
    return optim


# Evaluation callbacks


# Linear probes
#
# HEADLINE PROTOCOL (benchmarks/DECISION_LOG.md #7): every method, on both
# backbones, is probed with the SAME head on the SAME single representation:
#
#     ViT-S      -> final-layer CLS token          (embed_dim = d)
#     ResNet-50  -> final global-average-pooled    (embed_dim = d)
#     probe      -> Linear(BN_non-affine(z))
#
# Methods DO differ in their published probes -- MAE normalises with a non-affine
# BN, LeJEPA concatenates the last two CLS tokens under a LayerNorm, DINO
# concatenates the last four with no extra BN, and the ResNet-native contrastive
# methods (SimCLR/NNCLR/BarlowTwins) probe the bare pooled feature. Adopting each
# method's native probe would hand DINO 4d and LeJEPA 2d input features against
# MAE's 1d, i.e. different probe CAPACITY per method, which would confound the
# very comparison this benchmark exists to make. So the headline number fixes the
# representation and the head, and native probes are a separate opt-in.
#
# Each model file owns its own probe constructor (``build_probe``) so that the
# method-specific knowledge lives with the method, next to its forward(); the
# common protocol is simply what every one of them returns by default.


# DINO and LeJEPA both specify local crops at 96px against a 224px global crop
# (Caron et al. 2021 §3; LeJEPA's reference config uses local_size=96). Expressed
# as a ratio so non-224 datasets scale sensibly instead of inheriting a constant
# that is larger than their own images. The previous rule was h // 2, which gives
# 112 at 224 -- 1.36x the tokens per local view, and the reason multicrop needed
# a micro-batch of 32 to fit in 22GB.
LOCAL_CROP_RATIO = 96 / 224


def local_crop_size(ds_config, ratio: float = LOCAL_CROP_RATIO, min_size: int = 32):
    """Local-view size for multicrop, as a fraction of the dataset's image size."""
    h, w = ds_config.image_size
    return (max(int(round(h * ratio)), min_size), max(int(round(w * ratio)), min_size))


def common_probe(embed_dim: int, num_classes: int) -> nn.Module:
    """The shared benchmark probe head: non-affine BN then a linear layer.

    affine=False keeps this a pure whitening step -- no learnable scale/shift --
    so the only trained parameters are the linear layer's, and probe capacity is
    identical across methods. The BN matters because each SSL objective leaves an
    arbitrary per-feature scale in the embedding; without it, probe accuracy
    partly measures that scale rather than linear separability.
    """
    return nn.Sequential(
        nn.BatchNorm1d(embed_dim, affine=False, eps=1e-6),
        nn.Linear(embed_dim, num_classes),
    )


def bare_linear_probe(embed_dim: int, num_classes: int) -> nn.Module:
    """Unnormalised linear head — the native probe for SimCLR/NNCLR/BarlowTwins/DINO."""
    return nn.Linear(embed_dim, num_classes)


def build_linear_probe(embed_dim: int, num_classes: int, arch: str = "bn_linear") -> nn.Module:
    """Back-compat shim for the pre-per-model-probe API.

    ``arch="linear"`` reproduces the flat ``nn.Linear`` head used by every
    checkpoint written before 2026-09. recover_online_probe.py needs it: those
    state_dicts carry ``linear_probe.{weight,bias}``, whereas the common head
    produces ``linear_probe.{0,1}.*``, and loading one into the other under
    ``strict_loading = False`` does NOT raise -- it silently leaves the probe at
    random init and reports garbage accuracy.
    """
    if arch == "linear":
        return bare_linear_probe(embed_dim, num_classes)
    if arch == "bn_linear":
        return common_probe(embed_dim, num_classes)
    raise ValueError(f"unknown probe arch {arch!r} (expected 'bn_linear' or 'linear')")


def get_probe(model_name: str, embed_dim: int, num_classes: int, protocol: str = "common") -> nn.Module:
    """Build the online-probe head by delegating to the model's own constructor.

    ``protocol``:
      ``common``        the headline protocol (default) — identical for all methods.
      ``native``        the method's published probe. Only meaningful as a
                        SECONDARY result; for DINO/LeJEPA it additionally requires
                        forward() to emit a multi-layer CLS concatenation, and
                        those constructors raise unless ``embed_dim`` reflects it.
      ``legacy_linear`` bare nn.Linear, for reloading pre-2026-09 checkpoints.
    """
    if protocol == "legacy_linear":
        return bare_linear_probe(embed_dim, num_classes)
    module = _get_model_module(model_name)
    builder = getattr(module, "build_probe", None)
    if builder is None:
        log.warning("[probe] %s has no build_probe(); falling back to the common protocol", model_name)
        return common_probe(embed_dim, num_classes)
    return builder(embed_dim, num_classes, protocol)


def create_eval_callbacks(
    module: spt.Module,
    ds_config,
    embed_dim: int,
    model_name: str | None = None,
    probe_protocol: str = "common",
    probe_sweep: dict | None = None,
) -> list:
    """Create linear probe and KNN evaluation callbacks.

    ``model_name`` routes to that model's ``build_probe``; when omitted the
    common protocol is used directly (the two agree by construction for every
    model shipped here, so this only matters for ``protocol="native"``).
    ``probe_protocol`` is passed through — see :func:`get_probe`.
    """
    num_classes = ds_config.num_classes
    callbacks = []

    if num_classes > 0:
        metrics = {
            "top1": torchmetrics.classification.MulticlassAccuracy(num_classes),
            "top5": torchmetrics.classification.MulticlassAccuracy(num_classes, top_k=min(5, num_classes)),
        }
        def _head_factory(d, c, arch=None):
            # An explicit arch comes from the sweep and is uniform across methods,
            # so it deliberately bypasses the per-model build_probe: the whole
            # point of sweeping the head is that no method gets to pick its own.
            if arch is not None:
                return build_linear_probe(d, c, arch)
            if model_name is not None:
                return get_probe(model_name, d, c, probe_protocol)
            return build_linear_probe(
                d, c, "linear" if probe_protocol == "legacy_linear" else "bn_linear"
            )

        if probe_sweep:
            # K heads over the same frozen embedding, each at its own (lr, wd).
            # top1/top5 keep their names and become BEST-over-sweep, so anything
            # reading eval/linear_probe_top1_epoch keeps working unchanged.
            _archs = probe_sweep.get("archs", None)
            grid = expand_grid(
                probe_sweep["lr_scales"], probe_sweep["weight_decays"], _archs
            )
            probe_module = SweepLinearProbe(_head_factory, embed_dim, num_classes, grid)
            probe_loss = sweep_ce_loss
            metrics = build_sweep_metrics(
                probe_module.num_heads, num_classes, probe_module.tags(),
                per_head=probe_sweep.get("per_head_metrics", True),
            )
            log.info(
                "[probe] sweeping %d heads: archs=%s lr_scales=%s weight_decays=%s "
                "(top1/top5 report the best head)",
                probe_module.num_heads,
                list(_archs) if _archs else f"per-model ({model_name}.build_probe)",
                list(probe_sweep["lr_scales"]),
                list(probe_sweep["weight_decays"]),
            )
        else:
            probe_module = _head_factory(embed_dim, num_classes)
            probe_loss = nn.CrossEntropyLoss()

        linear_probe = spt.callbacks.OnlineProbe(
            module,
            name="linear_probe",
            input="embedding",
            target="label",
            probe=probe_module,
            loss=probe_loss,
            metrics=metrics,
        )
        callbacks.append(linear_probe)

        knn_probe = spt.callbacks.OnlineKNN(
            name="knn_probe",
            input="embedding",
            target="label",
            queue_length=20000,
            # Pin num_classes to the dataset's true count. Without it, OnlineKNN
            # infers class count from observed labels; for many-class datasets
            # (e.g. hasyv2, 369) the queue hasn't seen every class, so preds.shape[1]
            # != MulticlassAccuracy(num_classes) -> crash. Explicit == inferred for
            # datasets where all classes are seen, so no change to their results.
            num_classes=num_classes,
            metrics={
                "top1": torchmetrics.classification.MulticlassAccuracy(num_classes),
                "top5": torchmetrics.classification.MulticlassAccuracy(num_classes, top_k=min(5, num_classes)),
            },
            input_dim=embed_dim,
            k=10,
        )
        callbacks.append(knn_probe)

    # Representation-geometry monitors. RankMe is label-free; LiDAR uses
    # sequential surrogate classes from the queue (paper-native mode).
    callbacks.append(
        RankMe(
            name="rankme",
            target="embedding",
            queue_length=2048,
            target_shape=embed_dim,
        )
    )
    if num_classes > 0:
        lidar_n_classes = min(100, num_classes)
        callbacks.append(
            LiDAR(
                name="lidar",
                target="embedding",
                queue_length=max(2048, lidar_n_classes * 10),
                target_shape=embed_dim,
                n_classes=lidar_n_classes,
                samples_per_class=10,
            )
        )

    callbacks.append(LearningRateMonitor(logging_interval="step"))
    return callbacks


# Shared transforms & collation


def val_transform(ds_config) -> transforms.Compose:
    """Validation transform shared by all models: resize + normalize."""
    h, w = ds_config.image_size
    return transforms.Compose(
        transforms.RGB(),
        transforms.Resize((h, w)),
        transforms.ToImage(mean=ds_config.mean, std=ds_config.std),
    )


def ssl_augmentation(
    ds_config,
    crop_size: tuple[int, int],
    crop_scale: tuple[float, float],
    blur_p: float = 0.5,
    solarize_p: float = 0.0,
    interpolation: transforms.InterpolationMode = transforms.InterpolationMode.BILINEAR,
) -> transforms.Compose:
    """Standard SSL augmentation pipeline (crop → flip → color → blur → solarize → normalize).

    Shared by multiview and multicrop models.  Only the crop params, blur
    probability, solarization probability, and resize interpolation differ
    between them. Solarize is gated to RGB inputs.
    """
    ops = [
        transforms.RGB(),
        transforms.RandomResizedCrop(crop_size, scale=crop_scale, interpolation=interpolation),
        transforms.RandomHorizontalFlip(p=0.5),
    ]
    if ds_config.channels != 1:
        ops.extend(
            [
                transforms.ColorJitter(brightness=0.4, contrast=0.4, saturation=0.4, hue=0.1, p=0.8),
                transforms.RandomGrayscale(p=0.2),
            ]
        )
    ops.append(transforms.GaussianBlur(kernel_size=23, sigma=(0.1, 2.0), p=blur_p))
    if solarize_p > 0.0 and ds_config.channels != 1:
        ops.append(transforms.RandomSolarize(threshold=128, p=solarize_p))
    ops.append(transforms.ToImage(mean=ds_config.mean, std=ds_config.std))
    return transforms.Compose(*ops)


def collate_single(batch):
    """Collate for single-view batches: {"image": tensor, "label": int}."""
    return {
        "image": torch.stack([s["image"] for s in batch]),
        "label": torch.tensor([s["label"] for s in batch]),
    }


def collate_multiview(batch):
    """Collate for list-based multi-view: {"views": [view0, view1, ...]}."""
    first = batch[0]
    num_views = len(first["views"])
    views_list = []
    for v in range(num_views):
        view_dict = {"image": torch.stack([s["views"][v]["image"] for s in batch])}
        if "label" in first["views"][v]:
            view_dict["label"] = torch.tensor([s["views"][v]["label"] for s in batch])
        views_list.append(view_dict)
    return {"views": views_list}


def collate_multicrop(batch):
    """Collate for dict-based multi-view (DINO): {"global_1": {...}, ...}."""
    first = batch[0]
    collated = {}
    for view_name in first.keys():
        if isinstance(first[view_name], dict) and "image" in first[view_name]:
            view_dict = {"image": torch.stack([s[view_name]["image"] for s in batch])}
            if "label" in first[view_name]:
                view_dict["label"] = torch.tensor([s[view_name]["label"] for s in batch])
            collated[view_name] = view_dict
    return collated


# Model registry


def _get_model_module(model_name: str):
    """Import and return the model module by name."""
    from benchmarks.models import barlow_twins, dino, lejepa, mae, nnclr, simclr, supervised

    _MODULES = {
        "simclr": simclr,
        "dino": dino,
        "mae": mae,
        "lejepa": lejepa,
        "nnclr": nnclr,
        "barlow_twins": barlow_twins,
        "supervised": supervised,
    }
    if model_name not in _MODULES:
        available = ", ".join(_MODULES.keys())
        raise ValueError(f"Unknown model: {model_name}. Available: {available}")
    return _MODULES[model_name]


def build_module(cfg, ds_config) -> tuple[spt.Module, int]:
    """Build a module from Hydra config using the model registry.

    Returns (module, embedding_dim).
    """
    return _get_model_module(cfg.model.name).build(cfg, ds_config)


def get_transforms(model_name: str, ds_config, model_cfg=None):
    """Get (train_transform, val_transform, collate_fn) for a model.

    Each model defines its own ``create_transforms(ds_config, model_cfg=None)``
    that returns the appropriate transforms and collation function. ``model_cfg``
    is the per-model OmegaConf node (``cfg.model``) — models that need to read
    transform-specific knobs (e.g. DINO's ``num_global``/``num_local``) consume it.
    """
    return _get_model_module(model_name).create_transforms(ds_config, model_cfg)
