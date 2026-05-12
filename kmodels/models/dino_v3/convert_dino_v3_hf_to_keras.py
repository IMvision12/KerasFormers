import re
from typing import Dict

import numpy as np
from tqdm import tqdm

from kmodels.weight_utils.custom_exception import (
    WeightMappingError,
    WeightShapeMismatchError,
)
from kmodels.weight_utils.weight_split_torch_and_keras import split_model_weights
from kmodels.weight_utils.weight_transfer_torch_to_keras import (
    compare_keras_torch_names,
    transfer_weights,
)

DINOV3_VIT_VARIANTS = [
    ("dinov3_vits16", "facebook/dinov3-vits16-pretrain-lvd1689m"),
    ("dinov3_vitb16", "facebook/dinov3-vitb16-pretrain-lvd1689m"),
    ("dinov3_vitl16", "facebook/dinov3-vitl16-pretrain-lvd1689m"),
]

DINOV3_CONVNEXT_VARIANTS = [
    ("dinov3_convnext_tiny", "facebook/dinov3-convnext-tiny-pretrain-lvd1689m"),
    ("dinov3_convnext_small", "facebook/dinov3-convnext-small-pretrain-lvd1689m"),
    ("dinov3_convnext_base", "facebook/dinov3-convnext-base-pretrain-lvd1689m"),
    ("dinov3_convnext_large", "facebook/dinov3-convnext-large-pretrain-lvd1689m"),
]

DINOV3_VIT_NAME_MAPPING: Dict[str, str] = {
    "_": ".",
    "patch.embed": "embeddings.patch_embeddings",
    "blocks.": "model.layer.",
    "dense.1": "mlp.up_proj",
    "dense.2": "mlp.down_proj",
    "layernorm.1": "norm1",
    "layernorm.2": "norm2",
    "final.layernorm": "norm",
    "kernel": "weight",
    "gamma": "weight",
    "beta": "bias",
}


def _resolve_vit_attention(keras_weight_path: str):
    parts = keras_weight_path.split("/")
    layer_name = parts[-2]
    var_name = parts[-1]

    m = re.match(r"blocks_(\d+)_attn_(q|k|v)_proj$", layer_name)
    if m:
        idx = int(m.group(1))
        suffix = "weight" if "kernel" in var_name else "bias"
        return f"model.layer.{idx}.attention.{m.group(2)}_proj.{suffix}"

    m = re.match(r"blocks_(\d+)_attn_proj$", layer_name)
    if m:
        idx = int(m.group(1))
        suffix = "weight" if "kernel" in var_name else "bias"
        return f"model.layer.{idx}.attention.o_proj.{suffix}"

    return None


def _resolve_vit_layer_scale(keras_weight_path: str):
    layer_name = keras_weight_path.split("/")[-2]
    m = re.match(r"blocks_(\d+)_layerscale_(1|2)$", layer_name)
    if m is None:
        return None
    idx = int(m.group(1))
    which = m.group(2)
    return f"model.layer.{idx}.layer_scale{which}.lambda1"


def transfer_dinov3_vit_weights(keras_model, hf_state_dict):
    trainable, non_trainable = split_model_weights(keras_model)
    all_weights = trainable + non_trainable

    for keras_weight, keras_weight_name in tqdm(
        all_weights,
        total=len(all_weights),
        desc="Converting DinoV3",
        unit="weight",
    ):
        path = keras_weight.path

        if "cls_token" in path and "cls_token" in path.split("/")[-1]:
            hf_key = "embeddings.cls_token"
            if hf_key in hf_state_dict:
                keras_weight.assign(hf_state_dict[hf_key])
                continue

        if "register_tokens" in path:
            hf_key = "embeddings.register_tokens"
            if hf_key in hf_state_dict:
                keras_weight.assign(hf_state_dict[hf_key])
                continue

        if "_attn_" in path:
            hf_key = _resolve_vit_attention(path)
            if hf_key is None or hf_key not in hf_state_dict:
                raise WeightMappingError(keras_weight_name, str(hf_key))
            transfer_weights(keras_weight_name, keras_weight, hf_state_dict[hf_key])
            continue

        if "_layerscale_" in path:
            hf_key = _resolve_vit_layer_scale(path)
            if hf_key is None or hf_key not in hf_state_dict:
                raise WeightMappingError(keras_weight_name, str(hf_key))
            keras_weight.assign(hf_state_dict[hf_key])
            continue

        if "patch_embed" in path and len(keras_weight.shape) == 4:
            hf_key = "embeddings.patch_embeddings.weight"
            if hf_key in hf_state_dict:
                transfer_weights("conv_kernel", keras_weight, hf_state_dict[hf_key])
                continue

        torch_name = keras_weight_name
        for old, new in DINOV3_VIT_NAME_MAPPING.items():
            torch_name = torch_name.replace(old, new)

        if torch_name not in hf_state_dict:
            raise WeightMappingError(keras_weight_name, torch_name)

        torch_weight = hf_state_dict[torch_name]
        if not compare_keras_torch_names(
            keras_weight_name, keras_weight, torch_name, torch_weight
        ):
            raise WeightShapeMismatchError(
                keras_weight_name, keras_weight.shape, torch_name, torch_weight.shape
            )
        transfer_weights(keras_weight_name, keras_weight, torch_weight)


_VAR_MAP = {"kernel": "weight", "gamma": "weight", "bias": "bias", "beta": "bias"}

DINOV3_CONVNEXT_WEIGHT_MAPPING = {
    r"stem_conv_(kernel|bias)": "model.stages.0.downsample_layers.0.{v}",
    r"stem_layernorm_(gamma|beta)": "model.stages.0.downsample_layers.1.{v}",
    r"stages_(\d+)_downsampling_layernorm_(gamma|beta)": "model.stages.{0}.downsample_layers.0.{v}",
    r"stages_(\d+)_downsampling_conv_(kernel|bias)": "model.stages.{0}.downsample_layers.1.{v}",
    r"stages_(\d+)_blocks_(\d+)_layer_scale_variable": "model.stages.{0}.layers.{1}.gamma",
    r"stages_(\d+)_blocks_(\d+)_depthwise_conv_(kernel|bias)": "model.stages.{0}.layers.{1}.depthwise_conv.{v}",
    r"stages_(\d+)_blocks_(\d+)_layernorm_(gamma|beta)": "model.stages.{0}.layers.{1}.layer_norm.{v}",
    r"stages_(\d+)_blocks_(\d+)_conv_1_(kernel|bias)": "model.stages.{0}.layers.{1}.pointwise_conv1.{v}",
    r"stages_(\d+)_blocks_(\d+)_conv_2_(kernel|bias)": "model.stages.{0}.layers.{1}.pointwise_conv2.{v}",
    r"final_layernorm_(gamma|beta)": "layer_norm.{v}",
}


def _keras_to_hf_convnext(keras_name: str):
    for pattern, template in DINOV3_CONVNEXT_WEIGHT_MAPPING.items():
        m = re.match(pattern, keras_name)
        if m:
            groups = m.groups()
            var_group = groups[-1] if groups[-1] in _VAR_MAP else None
            idx_groups = groups if var_group is None else groups[:-1]
            v = _VAR_MAP[var_group] if var_group else ""
            return template.format(*idx_groups, v=v)
    return None


def transfer_dinov3_convnext_weights(keras_model, hf_state_dict):
    trainable, non_trainable = split_model_weights(keras_model)
    all_weights = trainable + non_trainable

    for keras_weight, keras_weight_name in tqdm(
        all_weights,
        total=len(all_weights),
        desc="Converting DinoV3",
        unit="weight",
    ):
        hf_key = _keras_to_hf_convnext(keras_weight_name)
        if hf_key is None or hf_key not in hf_state_dict:
            raise WeightMappingError(keras_weight_name, str(hf_key))

        hf_w = hf_state_dict[hf_key]

        if "layer_scale" in keras_weight_name:
            keras_weight.assign(hf_w)

        elif (
            "pointwise" in hf_key
            and len(hf_w.shape) == 2
            and len(keras_weight.shape) == 4
        ):
            keras_weight.assign(hf_w.T[np.newaxis, np.newaxis, :, :])
        else:
            transfer_weights(keras_weight_name, keras_weight, hf_w)


if __name__ == "__main__":
    import gc
    import os

    import keras
    import numpy as np
    import torch
    from transformers import AutoModel

    from kmodels.models.dino_v3 import (
        DinoV3ConvNeXtBackbone,
        DinoV3ViTBackbone,
    )

    HF_TOKEN = os.environ.get("HF_TOKEN")

    for variant, hf_id in DINOV3_VIT_VARIANTS:
        print(f"\n{'=' * 60}")
        print(f"Converting ViT: {variant}  <-  {hf_id}")
        print(f"{'=' * 60}")

        hf_model = AutoModel.from_pretrained(hf_id, token=HF_TOKEN).eval()
        hf_sd = {k: v.cpu().numpy() for k, v in hf_model.state_dict().items()}

        keras_model = DinoV3ViTBackbone.from_weights(
            variant,
            load_weights=False,
            input_shape=(224, 224, 3),
            include_normalization=False,
        )
        transfer_dinov3_vit_weights(keras_model, hf_sd)

        rng = np.random.default_rng(0)
        x_np = rng.standard_normal((1, 3, 224, 224)).astype(np.float32)
        with torch.no_grad():
            hf_out = (
                hf_model(pixel_values=torch.from_numpy(x_np))
                .last_hidden_state.cpu()
                .numpy()
            )
        k_in = np.transpose(x_np, (0, 2, 3, 1))
        # Backbone output is a list of intermediate features; take last
        last = keras_model(k_in, training=False)[-1]
        k_out = (
            last.detach().cpu().numpy() if hasattr(last, "detach") else np.asarray(last)
        )
        diff = float(np.abs(k_out - hf_out).max())
        assert diff < 1e-2, f"{variant}: max diff {diff:.2e}"
        print(f"  Verification OK (max diff = {diff:.2e})")

        out = f"{variant}.weights.h5"
        keras_model.save_weights(out)
        print(f"  Saved -> {out}")

        del keras_model, hf_model, hf_sd
        keras.backend.clear_session()
        gc.collect()
        torch.cuda.empty_cache() if torch.cuda.is_available() else None

    for variant, hf_id in DINOV3_CONVNEXT_VARIANTS:
        print(f"\n{'=' * 60}")
        print(f"Converting ConvNeXt: {variant}  <-  {hf_id}")
        print(f"{'=' * 60}")

        hf_model = AutoModel.from_pretrained(hf_id, token=HF_TOKEN).eval()
        hf_sd = {k: v.cpu().numpy() for k, v in hf_model.state_dict().items()}

        keras_model = DinoV3ConvNeXtBackbone.from_weights(
            variant,
            load_weights=False,
            input_shape=(224, 224, 3),
            include_normalization=False,
        )
        transfer_dinov3_convnext_weights(keras_model, hf_sd)

        rng = np.random.default_rng(0)
        x_np = rng.standard_normal((1, 3, 224, 224)).astype(np.float32)
        with torch.no_grad():
            hf_out_obj = hf_model(
                pixel_values=torch.from_numpy(x_np), output_hidden_states=True
            )
            hf_feat = hf_out_obj.hidden_states[-1].permute(0, 2, 3, 1).cpu().numpy()
        k_in = np.transpose(x_np, (0, 2, 3, 1))
        # Backbone output is a list of stage features; compare last
        last = keras_model(k_in, training=False)[-1]
        k_out = (
            last.detach().cpu().numpy() if hasattr(last, "detach") else np.asarray(last)
        )
        diff = float(np.abs(k_out - hf_feat).max())
        assert diff < 1e-2, f"{variant}: max diff {diff:.2e}"
        print(f"  Verification OK (max diff = {diff:.2e})")

        out = f"{variant}.weights.h5"
        keras_model.save_weights(out)
        print(f"  Saved -> {out}")

        del keras_model, hf_model, hf_sd
        keras.backend.clear_session()
        gc.collect()
        torch.cuda.empty_cache() if torch.cuda.is_available() else None
