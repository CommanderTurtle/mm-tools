from __future__ import annotations

from pathlib import Path

import torch

from .models.vision_transformer import DinoVisionTransformer


def dinov3_vitl16(weights: str | Path) -> DinoVisionTransformer:
    model = DinoVisionTransformer(
        img_size=224,
        patch_size=16,
        in_chans=3,
        pos_embed_rope_base=100,
        pos_embed_rope_normalize_coords="separate",
        pos_embed_rope_rescale_coords=2,
        pos_embed_rope_dtype="fp32",
        embed_dim=1024,
        depth=24,
        num_heads=16,
        ffn_ratio=4,
        qkv_bias=True,
        drop_path_rate=0.0,
        layerscale_init=1.0e-5,
        norm_layer="layernormbf16",
        ffn_layer="mlp",
        ffn_bias=True,
        proj_bias=True,
        n_storage_tokens=4,
        mask_k_bias=True,
        untie_global_and_local_cls_norm=False,
    )
    state = torch.load(Path(weights), map_location="cpu", weights_only=True)
    model.load_state_dict(state, strict=True)
    return model


__all__ = ["dinov3_vitl16"]
