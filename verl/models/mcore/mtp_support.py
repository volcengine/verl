# Copyright 2026 Bytedance Ltd. and/or its affiliates
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.
"""Compatibility helpers for Megatron-Core's native HybridModel MTP path."""

from functools import lru_cache
from inspect import signature


@lru_cache(maxsize=1)
def has_native_mtp_support() -> bool:
    """Return whether MCore can derive MTP labels and detach MTP heads natively."""
    try:
        from megatron.core.transformer import TransformerConfig
        from megatron.core.transformer.multi_token_prediction import process_mtp_loss

        config_fields = getattr(TransformerConfig, "__dataclass_fields__", {})
        has_detach_heads = hasattr(TransformerConfig, "mtp_detach_heads") or "mtp_detach_heads" in config_fields
        return has_detach_heads and "input_ids" in signature(process_mtp_loss).parameters
    except (ImportError, TypeError, ValueError):
        return False


def configure_native_hybrid_mtp(provider, mtp_config, transformer_overrides: dict) -> bool:
    """Validate and configure native HybridModel MTP before model construction."""
    is_hybrid_provider = bool(getattr(provider, "is_hybrid_model", False)) or any(
        provider_type.__name__ == "HybridModelProvider" for provider_type in type(provider).__mro__
    )
    if not is_hybrid_provider:
        return False
    if not mtp_config.enable:
        # A HybridProvider can infer a repeated MTP block from its retained
        # hybrid pattern even when mtp_num_layers is None. Override those
        # provider-specific defaults only after confirming the provider type.
        transformer_overrides.update(
            {
                "mtp_hybrid_override_pattern": None,
                "mtp_use_repeated_layer": False,
                "keep_mtp_spec_in_bf16": False,
            }
        )
        return False

    if not mtp_config.enable_train:
        raise ValueError(
            "HybridModel does not support model.mtp.enable=True with model.mtp.enable_train=False "
            "in this Megatron-Core version. Disable MTP entirely or enable MTP training."
        )
    if not has_native_mtp_support():
        raise RuntimeError(
            "HybridModel MTP training requires a Megatron-Core version with native "
            "process_mtp_loss(input_ids=...) and TransformerConfig.mtp_detach_heads support."
        )

    transformer_overrides["mtp_detach_heads"] = bool(mtp_config.detach_encoder)
    return True


def is_native_hybrid_model(model) -> bool:
    """Recognize native HybridModel MTP, including a multimodal language decoder."""
    if not has_native_mtp_support():
        return False
    try:
        from megatron.core.models.hybrid.hybrid_model import HybridModel
    except ImportError:
        return False
    return isinstance(model, HybridModel) or isinstance(getattr(model, "language_model", None), HybridModel)


def validate_nemotron_super_vl_config(hf_config, engine_config):
    """Require the expanded-sequence Bridge contract used by Super VL SFT."""
    if "NemotronH_Omni_Reasoning_V3" not in (getattr(hf_config, "architectures", None) or []):
        return
    try:
        from megatron.bridge.models.nemotron_omni.modeling_nemotron_omni import NemotronOmniModel
        from megatron.bridge.models.nemotron_omni.nemotron_omni_bridge import Nemotron35SuperVLBridge  # noqa: F401
    except ImportError as error:
        raise RuntimeError(
            "Nemotron 3.5 Super VL requires Megatron-Bridge with Nemotron35SuperVLBridge and "
            "expanded-sequence NemotronOmniModel support; the pinned Bridge 0.6.2 predates it. "
            "See docs/advance/mtp.md for matching Bridge and Megatron-Core source revisions."
        ) from error
    if getattr(NemotronOmniModel, "model_owns_packing", True):
        raise RuntimeError("Nemotron 3.5 Super VL requires Bridge's expanded-sequence NemotronOmniModel.")
    if engine_config.context_parallel_size != 1 or engine_config.dynamic_context_parallel:
        raise ValueError("Nemotron 3.5 Super VL currently requires context_parallel_size=1 and dynamic CP disabled.")
    if engine_config.use_fused_kernels:
        raise ValueError("Nemotron 3.5 Super VL currently requires engine.use_fused_kernels=False.")
