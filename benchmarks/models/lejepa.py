"""LeJEPA: invariance + sliced Epps-Pulley regularization (multi-crop)."""

from __future__ import annotations

import timm
import stable_pretraining as spt
from torch import nn
from stable_pretraining.data import transforms
from stable_pretraining.methods.lejepa import LeJEPA, LeJEPAOutput

from benchmarks.models import (
    build_optim_config,
    collate_multicrop,
    local_crop_size,
    resolve_backbone_family,
    resolve_backbone_name,
    val_transform,
)


NUM_GLOBAL = 2
NUM_LOCAL = 6


def _photometric(ds_config) -> list:
    ops = [transforms.RandomHorizontalFlip(p=0.5)]
    if ds_config.channels != 1:
        ops.extend(
            [
                transforms.ColorJitter(brightness=0.4, contrast=0.4, saturation=0.2, hue=0.1, p=0.8),
                transforms.RandomGrayscale(p=0.2),
            ]
        )
    ops.append(transforms.GaussianBlur(kernel_size=23, sigma=(0.1, 2.0), p=0.5))
    if ds_config.channels != 1:
        ops.append(transforms.RandomSolarize(threshold=128, p=0.2))
    return ops


def _crop_transform(ds_config, size, scale):
    return transforms.Compose(
        transforms.RGB(),
        transforms.RandomResizedCrop(size, scale=scale),
        *_photometric(ds_config),
        transforms.ToImage(mean=ds_config.mean, std=ds_config.std),
    )


def create_transforms(ds_config, model_cfg=None):
    h, w = ds_config.image_size
    local_size = local_crop_size(ds_config)

    global_aug = _crop_transform(ds_config, (h, w), scale=(0.3, 1.0))
    local_aug = _crop_transform(ds_config, local_size, scale=(0.05, 0.3))

    transform_dict = {
        **{f"global_{i + 1}": global_aug for i in range(NUM_GLOBAL)},
        **{f"local_{i + 1}": local_aug for i in range(NUM_LOCAL)},
    }
    train = transforms.MultiViewTransform(transform_dict)
    return train, val_transform(ds_config), collate_multicrop


def forward(self, batch, stage):
    """LeJEPA forward: multi-view invariance + Epps-Pulley goodness-of-fit (SIGReg).

    Expects ``self`` to have attributes:
        - ``backbone``: Feature extraction network
        - ``projector``: Projection head
        - ``sigreg``: :class:`SlicedEppsPulley` module
        - ``lamb``: SIGReg weight λ

    Batch format:
        - Training: dict of named views (``"global_0"``, ``"local_2"``, etc.)
        - Eval: single dict with ``"image"`` key

    Args:
        self: Module instance (automatically bound).
        batch: Named view dict or single-image dict.
        stage: Training stage ('train', 'val', or 'test').

    Returns:
        Dictionary with ``"loss"``, ``"embedding"``, and optionally ``"label"``.
    """
    out = {}

    images = batch.get("image")
    if stage == "fit":
        global_views = [batch[key]["image"] for key in batch if key.startswith("global")]
        local_views = [batch[key]["image"] for key in batch if key.startswith("local")]
        labels = next(batch[key]["label"] for key in batch if key.startswith("global") or key.startswith("local"))

        output: LeJEPAOutput = self.model.forward(global_views=global_views, local_views=local_views, images=images)
        out["label"] = labels.repeat(len(global_views))
    else:
        output: LeJEPAOutput = self.model.forward(images=images)
        out["label"] = batch["label"].long()

    out["loss"] = output.loss
    out["embedding"] = output.embedding

    self.log(
        f"{stage}/sigreg",
        output.sigreg_loss,
        on_step=True,
        on_epoch=True,
        sync_dist=True,
    )
    self.log(f"{stage}/inv", output.inv_loss, on_step=True, on_epoch=True, sync_dist=True)
    self.log(f"{stage}/loss", output.loss, on_step=True, on_epoch=True, sync_dist=True)
    return out


def _build_lejepa(**kwargs) -> LeJEPA:
    """Construct LeJEPA, injecting ``embed_dim`` for non-ViT backbones.

    ``LeJEPA.__init__`` reads ``self.backbone.embed_dim`` immediately after
    building the backbone via ``timm.create_model`` and uses it to size the
    projector, but timm ResNets expose ``num_features`` rather than
    ``embed_dim``. We temporarily wrap ``timm.create_model`` so the returned
    backbone carries an ``embed_dim`` alias — the only seam between the
    backbone's creation and the attribute read. This keeps the vendored
    stable_pretraining code untouched (survives reinstalls) and is reverted in
    ``finally``.
    """
    orig_create_model = timm.create_model

    def _with_embed_dim(name, *args, **create_kwargs):
        model = orig_create_model(name, *args, **create_kwargs)
        if not hasattr(model, "embed_dim"):
            model.embed_dim = model.num_features
        return model

    timm.create_model = _with_embed_dim
    try:
        return LeJEPA(**kwargs)
    finally:
        timm.create_model = orig_create_model


def build(cfg, ds_config) -> tuple[spt.Module, int]:
    backbone_name = resolve_backbone_name(cfg.backbone, ds_config)
    family = resolve_backbone_family(cfg.backbone)
    _dpr = cfg.model.get("drop_path_rate", None)
    drop_path_rate = 0.0 if _dpr is None else float(_dpr.get(family, 0.0))
    lejepa_kwargs = dict(
        encoder_name=backbone_name,
        n_slices=cfg.model.loss.num_slices,
        t_max=cfg.model.loss.t_max,
        n_points=cfg.model.loss.n_points,
        lamb=cfg.model.loss.lamb,
        pretrained=False,
        drop_path_rate=drop_path_rate,
    )
    if family == "resnet":
        lejepa = _build_lejepa(**lejepa_kwargs)
    else:
        lejepa = LeJEPA(**lejepa_kwargs)
    embed_dim = lejepa.embed_dim
    module = spt.Module(
        model=lejepa,
        backbone=lejepa.backbone,
        projector=lejepa.projector,
        forward=forward,
        optim=build_optim_config(cfg.model, cfg.backbone),
    )
    return module, embed_dim


def build_probe(embed_dim: int, num_classes: int, protocol: str = "common") -> nn.Module:
    """LeJEPA's probe head: a BARE nn.Linear, no BatchNorm.

    This is the one method whose head departs from the shared BN-then-Linear
    protocol, and the departure is deliberate. The non-affine BatchNorm rescales
    every feature dimension to unit variance, which helps an embedding whose
    dimensions sit at wildly different scales but HURTS a badly-conditioned one,
    because it lifts near-null directions -- noise -- up to the same scale as
    the informative ones. LeJEPA's embedding is by far the worst-conditioned in
    the benchmark (condition number ~5e3 on imagenet100 against ~3.4e3 for
    simclr/barlow_twins ViT), and the reference implementation this method is
    calibrated against (le-wm-collapse) probes with a bare Linear and reaches
    65.9% where our BN head reached 62.5%.

    Note for the writeup: this makes LeJEPA's probe non-identical to the other
    six methods', so the probe protocol is no longer a fully controlled variable
    across the grid and should be stated as such. DECISION_LOG #7.

    Native: LayerNorm over the CONCATENATION of the last two CLS tokens, then a
    linear layer. That needs a 2*d feature, so it is not a drop-in: forward()
    currently emits a single d-dim CLS token, and building a 2*d probe over it
    would silently mis-shape the head.
    """
    from benchmarks.models import bare_linear_probe

    if protocol == "common":
        return bare_linear_probe(embed_dim, num_classes)
    if protocol == "native":
        raise NotImplementedError(
            "lejepa native probe = LayerNorm over concat(CLS[-2:]) -> Linear, which needs "
            "forward() to emit a 2*embed_dim feature. Change forward() to concatenate the "
            "last two layers' CLS tokens and pass the doubled embed_dim before using this."
        )
    raise ValueError(f"lejepa: unknown probe protocol {protocol!r}")
