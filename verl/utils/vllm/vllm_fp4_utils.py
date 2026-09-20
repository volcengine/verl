# Copyright 2025 Bytedance Ltd. and/or its affiliates
# Copyright (c) 2025, NVIDIA CORPORATION. All rights reserved.
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

"""Refit support for vLLM's MXFP4 and NVFP4 routed experts.

Reloading these experts means undoing the kernel's weight conversion: the refit
stream carries checkpoint-layout tensors while the live parameters hold whatever
layout the selected backend rewrote them into. Each expert param is handed a
checkpoint-layout buffer to absorb the reload, then the backend's conversion is
replayed and folded back into the live storage, so the addresses the CUDA graph
captured stay put.

Backends differ only in how much of that buffer has to be a real allocation.
A param whose kernel layout spans the same bytes as the checkpoint one -- the
expert weights under both DeepGEMM and Marlin -- stages as a reinterpret of its
own storage and costs nothing. Only the block scales, which change element
count, need an allocation, and those are a sixteenth of the weights.

``verl/utils/vllm/vllm_quant_utils.py`` is the entry point that drives these.
"""

import logging
from dataclasses import replace
from unittest.mock import patch

import torch

from verl.utils.vllm.vllm_fp8_utils import _scale_from_amax, dsv4_fp8_linear_leaf, quantize_dsv4_fp8_linear

logger = logging.getLogger(__name__)

# Default FP8 weight block size for DeepSeek-V4-Flash (128x128). DeepSeek-V4.1-Flash
# uses 32x32; pass the correct value via iter_deepseek_v4_weights(block_size=...).
_DSV4_DEFAULT_BLOCK_SIZE = 128

_MXFP4_SF_BLOCK = 32
_MXFP4_LIVE_ATTR = "_verl_mxfp4_live_params"
_NVFP4_SF_BLOCK = 16
_NVFP4_LIVE_ATTR = "_verl_nvfp4_live_params"


def install_mxfp4_mxfp8_compressed_tensors_patch():
    """Teach vLLM compressed-tensors to honor MXFP8 expert activations.

    vLLM 0.29 recognizes MXFP4 compressed-tensors weights but ignores their
    input-activation scheme and unconditionally constructs its W4A4 method on
    Blackwell.  Reuse vLLM's canonical MXFP4 method so its oracle can select an
    actual MXFP4×MXFP8 backend while retaining the compressed-tensors packed
    parameter names expected by the loader.
    """
    from vllm.model_executor.layers.fused_moe import FusedMoEMethodBase
    from vllm.model_executor.layers.fused_moe.oracle.mxfp4 import (
        kMxfp8Dynamic,
        select_mxfp4_moe_backend,
    )
    from vllm.model_executor.layers.quantization.compressed_tensors.compressed_tensors_moe import (
        CompressedTensorsMoEMethod,
        compressed_tensors_moe_w4a4_mxfp4,
    )
    from vllm.model_executor.layers.quantization.mxfp4 import Mxfp4MoEMethod

    CompressedTensorsW4A4Mxfp4MoEMethod = compressed_tensors_moe_w4a4_mxfp4.CompressedTensorsW4A4Mxfp4MoEMethod
    if getattr(CompressedTensorsMoEMethod, "_verl_mxfp4_mxfp8_patch", False):
        return

    class CompressedTensorsW4A8Mxfp4MoEMethod(Mxfp4MoEMethod):
        """Compressed-tensors MXFP4 weights with dynamic MXFP8 activations."""

        _verl_uses_packed_checkpoint_names = True

        def __init__(self, moe):
            FusedMoEMethodBase.__init__(self, moe)
            self.weight_dtype = "mxfp4"
            self.group_size = _MXFP4_SF_BLOCK
            # TRTLLM's MXFP4×MXFP8 path is numerically incorrect for Qwen3.5
            # on vLLM 0.29, while FlashInfer CUTLASS matches the BF16 and
            # DeepGEMM references. Keep explicit user choices intact, but make
            # the verified backend the default for verl's MXFP4 preset.
            selection_moe = replace(moe, moe_backend="flashinfer_cutlass") if moe.moe_backend == "auto" else moe
            self.mxfp4_backend, self.experts_cls = select_mxfp4_moe_backend(selection_moe, activation_key=kMxfp8Dynamic)
            self.max_capture_size = moe.max_capture_size
            self._cache_permute_indices = {}
            self.moe_kernel = None
            self.w13_precision_config = None
            self.w2_precision_config = None

        def create_weights(
            self,
            layer,
            num_experts,
            hidden_size,
            intermediate_size_per_partition,
            params_dtype,
            **extra_weight_attrs,
        ):
            CompressedTensorsW4A4Mxfp4MoEMethod.create_weights(
                self,
                layer,
                num_experts,
                hidden_size,
                intermediate_size_per_partition,
                params_dtype,
                **extra_weight_attrs,
            )
            self.num_experts = num_experts
            self.intermediate_size = intermediate_size_per_partition
            self.hidden_size = hidden_size

        def process_weights_after_loading(self, layer):
            # The compressed-tensors loader uses ``*_packed`` only for the
            # initial load.  Refit staging restores the canonical names.
            if hasattr(layer, "w13_weight_packed"):
                layer.w13_weight = torch.nn.Parameter(layer.w13_weight_packed.data, requires_grad=False)
                delattr(layer, "w13_weight_packed")
                layer.w2_weight = torch.nn.Parameter(layer.w2_weight_packed.data, requires_grad=False)
                delattr(layer, "w2_weight_packed")
            return super().process_weights_after_loading(layer)

    original = CompressedTensorsMoEMethod.get_moe_method

    def get_moe_method(quant_config, layer, layer_name):
        quant_config._add_fused_moe_to_target_scheme_map()
        schemes = [
            quant_config.get_scheme_dict(layer, layer_name + projection)
            for projection in (".0.gate_proj", ".0.up_proj", ".0.down_proj")
        ]
        scheme = schemes[-1]
        if not all(candidate == scheme for candidate in schemes):
            return original(quant_config, layer, layer_name)
        weight_quant = None if scheme is None else scheme.get("weights")
        input_quant = None if scheme is None else scheme.get("input_activations")
        if quant_config._is_mxfp4(weight_quant) and quant_config._is_mxfp8(input_quant):
            logger.info("Using MXFP4 weights with dynamic MXFP8 activations for compressed-tensors MoE")
            return CompressedTensorsW4A8Mxfp4MoEMethod(layer.moe_config)
        return original(quant_config, layer, layer_name)

    CompressedTensorsMoEMethod.get_moe_method = staticmethod(get_moe_method)
    CompressedTensorsMoEMethod._verl_mxfp4_mxfp8_patch = True


def install_nvfp4_cutlass_compressed_tensors_patch():
    """Make verl's NVFP4 W4A4 preset select the verified CUTLASS backend."""
    from vllm.model_executor.layers.quantization.compressed_tensors.compressed_tensors_moe import (
        compressed_tensors_moe_w4a4_nvfp4,
    )

    CompressedTensorsW4A4Nvfp4MoEMethod = compressed_tensors_moe_w4a4_nvfp4.CompressedTensorsW4A4Nvfp4MoEMethod
    if getattr(CompressedTensorsW4A4Nvfp4MoEMethod, "_verl_cutlass_patch", False):
        return
    original_init = CompressedTensorsW4A4Nvfp4MoEMethod.__init__

    def __init__(self, moe, layer_name=None, use_a16=False):
        if use_a16:
            raise NotImplementedError("verl supports NVFP4 only as W4A4 routed experts")
        selection_moe = replace(moe, moe_backend="flashinfer_cutlass") if moe.moe_backend == "auto" else moe
        original_init(self, selection_moe, layer_name=layer_name, use_a16=False)

    CompressedTensorsW4A4Nvfp4MoEMethod.__init__ = __init__
    CompressedTensorsW4A4Nvfp4MoEMethod._verl_cutlass_patch = True


# MXFP4 quantization — inlined from Megatron-Bridge quantization_utils (no megatron import here).
_FP4_E2M1_MAX = 6.0


def _quantize_mxfp4_e2m1_like_scale(weight, source_scale, *, name="", block_size=_MXFP4_SF_BLOCK):
    """Quantize a 2-D weight to packed MXFP4 E2M1 using source scale geometry."""
    if weight.ndim != 2:
        label = f" for {name!r}" if name else ""
        raise RuntimeError(f"MXFP4 quantized export expects a 2-D weight{label}, got {weight.ndim}D")
    rows, cols = weight.shape
    if cols % 2 != 0 or cols % block_size != 0 or source_scale.shape != (rows, cols // block_size):
        label = f" for {name!r}" if name else ""
        raise RuntimeError(
            f"Unsupported MXFP4 geometry{label}: weight={tuple(weight.shape)} scale={tuple(source_scale.shape)}"
        )
    weight_f32 = weight.to(torch.float32)
    packed = torch.empty((rows, cols // 2), dtype=torch.uint8, device=weight.device)
    scale_f32 = torch.empty(tuple(source_scale.shape), dtype=torch.float32, device=weight.device)
    boundaries = torch.tensor([0.25, 0.75, 1.25, 1.75, 2.5, 3.5, 5.0], dtype=torch.float32, device=weight.device)
    max_chunk_elements = 16_000_000
    rows_per_chunk = max(1, min(rows, max_chunk_elements // max(cols, 1)))
    scale_cols = source_scale.shape[1]
    for row_start in range(0, rows, rows_per_chunk):
        row_end = min(row_start + rows_per_chunk, rows)
        chunk = weight_f32[row_start:row_end].reshape(-1, scale_cols, block_size)
        chunk_amax = chunk.abs().amax(dim=-1)
        if source_scale.dtype == torch.uint8:
            unrounded_scale = torch.where(
                chunk_amax > 0,
                chunk_amax / _FP4_E2M1_MAX,
                torch.ones_like(chunk_amax),
            )
            chunk_scale = torch.exp2(torch.ceil(torch.log2(unrounded_scale)).clamp(min=-127, max=127))
        else:
            chunk_scale = _scale_from_amax(chunk_amax, _FP4_E2M1_MAX, source_scale.dtype)
        scale_f32[row_start:row_end] = chunk_scale
        normalized = chunk / chunk_scale[:, :, None]
        codes = torch.bucketize(normalized.abs(), boundaries).to(torch.uint8)
        codes = (codes | ((normalized < 0).to(torch.uint8) * 8)).reshape(row_end - row_start, cols)
        lo = codes[:, 0::2].to(torch.int16)
        hi = codes[:, 1::2].to(torch.int16)
        packed[row_start:row_end] = (lo | (hi << 4)).to(torch.uint8)
    if source_scale.dtype == torch.uint8:
        output_scale = (torch.log2(scale_f32).round() + 127).clamp(min=0, max=254).to(torch.uint8)
    else:
        output_scale = scale_f32.to(dtype=source_scale.dtype)
    return packed.contiguous().view(torch.int8), output_scale


_DEEPSEEK_V4_MODEL_TYPES = ("deepseek_v4", "deepseek_v41")


def is_deepseek_v4_model(model):
    if model is None:
        return False

    for obj in (model, getattr(model, "config", None), getattr(model, "hf_config", None)):
        if obj is not None and getattr(obj, "model_type", None) is not None:
            return obj.model_type in _DEEPSEEK_V4_MODEL_TYPES

    text_config = getattr(getattr(model, "config", None), "text_config", None)
    return getattr(text_config, "model_type", None) in _DEEPSEEK_V4_MODEL_TYPES


def _quantize_expert_to_mxfp4(weight):
    """Quantize a 2-D bf16 expert weight to packed MXFP4 E2M1 + e8m0 scale
    (geometry [out, in] -> scale [out, in//32])."""
    rows, cols = weight.shape
    scale_geom = torch.empty(rows, cols // _MXFP4_SF_BLOCK, dtype=torch.uint8, device=weight.device)
    packed, scale = _quantize_mxfp4_e2m1_like_scale(weight, scale_geom, name="dsv4_expert")
    return packed, scale


def iter_deepseek_v4_weights(weights, block_size=_DSV4_DEFAULT_BLOCK_SIZE):
    """Pass the refit stream through untouched apart from a dtype reinterpret.

    A DSv4 checkpoint already ships quantized experts, so unlike the BF16 path
    there is nothing to quantize here. The expert tensors only need to be seen
    as the raw ``uint8`` byte layout that ``Mxfp4MoEMethod`` allocated.
    """
    for name, weight in weights:
        if ".experts." in name and name.endswith(".weight") and weight.dtype == torch.bfloat16:
            packed, scale = _quantize_expert_to_mxfp4(weight)
            yield name, packed
            yield name[: -len(".weight")] + ".scale", scale
            continue
        if ".experts." in name and weight.dtype in (torch.int8, torch.float8_e8m0fnu):
            weight = weight.view(torch.uint8)
            yield name, weight
            continue
        fp8_leaf = dsv4_fp8_linear_leaf(name)
        if fp8_leaf is not None and weight.dtype == torch.bfloat16:
            fp8_weight, scale = quantize_dsv4_fp8_linear(weight, fp8_leaf, block_size=block_size)
            yield name, fp8_weight
            yield name[: -len(".weight")] + ".scale", scale
            continue
        yield name, weight


def _is_mxfp4_fused_moe_module(module):
    from vllm.model_executor.layers.fused_moe import RoutedExperts
    from vllm.model_executor.layers.quantization.mxfp4 import Mxfp4MoEMethod

    return isinstance(module, RoutedExperts) and isinstance(module.quant_method, Mxfp4MoEMethod)


def _refittable_mxfp4_backends():
    """Backends whose weight conversion can be replayed onto live storage.

    Two properties qualify a backend. Its conversion must be a pure function of
    the checkpoint layout, so replaying it after a reload reproduces the same
    inference layout. And it must publish the result through
    ``replace_parameter``, which is the hook ``_replace_parameter_in_place``
    intercepts to redirect the write into the captured storage.

    Triton is the notable exclusion: it assigns the weights as non-Parameter
    wrappers and parks the scales on the quant method, so the buffers its kernel
    reads are not reachable as parameters at all.
    """
    from vllm.model_executor.layers.fused_moe.oracle.mxfp4 import Mxfp4MoeBackend

    return (
        Mxfp4MoeBackend.FLASHINFER_CUTLASS_MXFP4_MXFP8,
        Mxfp4MoeBackend.DEEPGEMM_MXFP4,
        Mxfp4MoeBackend.MARLIN,
        Mxfp4MoeBackend.BATCHED_MARLIN,
        Mxfp4MoeBackend.AITER_MXFP4_BF16,
    )


def _mxfp4_checkpoint_layout(module):
    """Layout of the expert params before kernel post-processing rewrites them.

    Mirrors ``Mxfp4MoEMethod.create_weights``. These are not guesses: vLLM
    re-asserts the same shapes at the top of ``_setup_kernel``, so a refit that
    hands back anything else fails loudly there. The third element is the
    ``quant_method`` tag ``RoutedExperts.weight_loader`` dispatches on, which
    ``replace_parameter`` does not carry over and must be reattached.
    """
    quant_method = module.quant_method
    num_experts = quant_method.num_experts
    intermediate = quant_method.intermediate_size
    hidden = quant_method.hidden_size
    return {
        "w13_weight": ((num_experts, 2 * intermediate, hidden // 2), torch.uint8, None),
        "w2_weight": ((num_experts, hidden, intermediate // 2), torch.uint8, None),
        "w13_weight_scale": ((num_experts, 2 * intermediate, hidden // _MXFP4_SF_BLOCK), torch.uint8, "block"),
        "w2_weight_scale": ((num_experts, hidden, intermediate // _MXFP4_SF_BLOCK), torch.uint8, "block"),
        # Listed unconditionally: models without MoE bias never registered these
        # and are skipped when the parameter turns up missing. Leaving them out
        # would instead let Marlin's bias permute fall through to the real
        # ``replace_parameter`` and quietly move the buffer.
        "w13_bias": ((num_experts, 2 * intermediate), torch.bfloat16, None),
        "w2_bias": ((num_experts, hidden), torch.bfloat16, None),
    }


def _mxfp4_staging_data(param, shape, dtype):
    """Checkpoint-layout tensor for ``load_weights`` to write into.

    Reuses the live storage whenever it spans the same number of bytes, which
    covers more than the params a backend left alone. Marlin's repack is a
    permutation of 4-bit values, so its int32 tiles occupy exactly the bytes the
    uint8 checkpoint weight did; reinterpreting them costs nothing and keeps the
    reload landing where the kernel reads. That is what stops a refit from
    needing a second copy of the experts, which for the expert weights is the
    difference between a negligible allocation and doubling MoE memory.

    Replaying the conversion reads this buffer in full and builds its result in a
    fresh tensor before ``_replace_parameter_in_place`` writes back, so aliasing
    the destination is safe.
    """
    data = param.data
    shape = torch.Size(shape)
    if data.dtype == dtype and data.shape == shape:
        return data
    if data.is_contiguous() and data.numel() * data.element_size() == shape.numel() * dtype.itemsize:
        return data.flatten().view(dtype).reshape(shape)
    # Zero rather than empty: a param the refit stream happens to skip then
    # collapses the layer's output instead of feeding the kernel whatever was
    # left in the freed memory.
    return torch.zeros(shape, dtype=dtype, device=param.device)


def _stage_mxfp4_moe_params(module):
    """Expose checkpoint-layout buffers without moving any live storage.

    Each expert param is handed a buffer in the layout its ``weight_loader``
    expects, preferring a reinterpret of the param's own storage so the reload
    lands where the kernel reads. ``_process_mxfp4_moe_params`` then replays the
    backend's conversion and folds the result back into the live storage.
    """
    live = {}
    uses_packed_names = getattr(module.quant_method, "_verl_uses_packed_checkpoint_names", False)
    for name, (shape, dtype, scale_kind) in _mxfp4_checkpoint_layout(module).items():
        param = getattr(module, name, None)
        if not isinstance(param, torch.nn.Parameter):
            continue
        live[name] = param

        staged = torch.nn.Parameter(_mxfp4_staging_data(param, shape, dtype), requires_grad=False)
        staged.weight_loader = module.weight_loader
        if scale_kind is not None:
            staged.quant_method = scale_kind
        checkpoint_name = f"{name}_packed" if uses_packed_names and name in ("w13_weight", "w2_weight") else name
        setattr(module, checkpoint_name, staged)

    setattr(module, _MXFP4_LIVE_ATTR, live)


def _replace_parameter_in_place(layer, param_name, new_data, prefer_copy=False):
    """Fold post-processing output into the parameter the CUDA graph captured.

    Reinstating the live parameter here rather than after
    ``process_weights_after_loading`` returns is deliberate: the tail of
    ``_setup_kernel`` rebuilds ``moe_quant_config`` and ``moe_kernel`` from
    whatever is on the layer at that moment, and those cache tensor references.
    Swapping back later would leave the kernel pointing at the temporaries.
    """
    from vllm.model_executor.utils import replace_parameter

    live = getattr(layer, _MXFP4_LIVE_ATTR, None) or {}
    param = live.pop(param_name, None)
    if param is None or new_data is None:
        return replace_parameter(layer, param_name, new_data, prefer_copy)

    if isinstance(new_data, torch.nn.Parameter):
        new_data = new_data.data

    if new_data.shape != param.shape or new_data.dtype != param.dtype:
        raise RuntimeError(
            f"mxfp4 refit re-derived {param_name} as {tuple(new_data.shape)}/{new_data.dtype}, "
            f"but the live parameter is {tuple(param.shape)}/{param.dtype}; "
            "its storage cannot be updated in place."
        )
    if new_data.data_ptr() != param.data_ptr():
        param.data.copy_(new_data)
    setattr(layer, param_name, param)


def _is_nvfp4_fused_moe_module(module):
    from vllm.model_executor.layers.fused_moe import RoutedExperts
    from vllm.model_executor.layers.quantization.compressed_tensors.compressed_tensors_moe import (
        compressed_tensors_moe_w4a4_nvfp4,
    )

    CompressedTensorsW4A4Nvfp4MoEMethod = compressed_tensors_moe_w4a4_nvfp4.CompressedTensorsW4A4Nvfp4MoEMethod
    return isinstance(module, RoutedExperts) and isinstance(module.quant_method, CompressedTensorsW4A4Nvfp4MoEMethod)


def _nvfp4_checkpoint_layout(module):
    """Checkpoint tensors consumed by vLLM's NVFP4 fused-expert loader."""
    num_experts = module.num_experts
    intermediate = module.intermediate_size_per_partition
    hidden = module.hidden_size
    w13_shards = 2 if module.quant_method.moe.is_act_and_mul else 1
    tensor = "tensor"
    group = "group"
    return {
        "w13_weight": (
            (num_experts, w13_shards * intermediate, hidden // 2),
            torch.uint8,
            None,
            "w13_weight_packed",
        ),
        "w2_weight": (
            (num_experts, hidden, intermediate // 2),
            torch.uint8,
            None,
            "w2_weight_packed",
        ),
        "w13_weight_scale": (
            (num_experts, w13_shards * intermediate, hidden // _NVFP4_SF_BLOCK),
            torch.float8_e4m3fn,
            group,
            "w13_weight_scale",
        ),
        "w2_weight_scale": (
            (num_experts, hidden, intermediate // _NVFP4_SF_BLOCK),
            torch.float8_e4m3fn,
            group,
            "w2_weight_scale",
        ),
        "w13_weight_global_scale": (
            (num_experts, w13_shards),
            torch.float32,
            tensor,
            "w13_weight_global_scale",
        ),
        "w2_weight_global_scale": (
            (num_experts,),
            torch.float32,
            tensor,
            "w2_weight_global_scale",
        ),
        "w13_input_global_scale": (
            (num_experts, w13_shards),
            torch.float32,
            tensor,
            "w13_input_global_scale",
        ),
        "w2_input_global_scale": (
            (num_experts,),
            torch.float32,
            tensor,
            "w2_input_global_scale",
        ),
    }


def _stage_nvfp4_moe_params(module):
    live = {}
    layout = _nvfp4_checkpoint_layout(module)
    for live_name, (shape, dtype, scale_kind, checkpoint_name) in layout.items():
        param = getattr(module, live_name, None)
        if not isinstance(param, torch.nn.Parameter):
            continue
        # Global scales stay in checkpoint layout and are not replaced by
        # post-processing, so loading them directly is address-safe.
        if live_name.endswith("global_scale"):
            continue
        live[live_name] = param
        staged = torch.nn.Parameter(_mxfp4_staging_data(param, shape, dtype), requires_grad=False)
        staged.weight_loader = module.weight_loader
        if scale_kind is not None:
            staged.quant_method = scale_kind
        setattr(module, checkpoint_name, staged)

    # These are derived from the global scales and replaced by the official
    # post-process even though they have no checkpoint-side staging tensor.
    for name in ("w13_weight_scale_2", "w2_weight_scale_2"):
        param = getattr(module, name, None)
        if isinstance(param, torch.nn.Parameter):
            live[name] = param
    # CUDA graphs capture these activation-scale pointers too.  The upstream
    # post-process assigns freshly derived tensors instead of Parameters, so
    # preserve their initial storage and copy each refit's values into it.
    for name in ("w13_input_scale", "w2_input_scale"):
        tensor = getattr(module, name, None)
        if isinstance(tensor, torch.Tensor):
            live[name] = tensor
    setattr(module, _NVFP4_LIVE_ATTR, live)


def _replace_nvfp4_parameter_in_place(layer, param_name, new_data, prefer_copy=False):
    from vllm.model_executor.utils import replace_parameter

    live = getattr(layer, _NVFP4_LIVE_ATTR, None) or {}
    param = live.pop(param_name, None)
    if param is None or new_data is None:
        return replace_parameter(layer, param_name, new_data, prefer_copy)
    if isinstance(new_data, torch.nn.Parameter):
        new_data = new_data.data
    if new_data.shape != param.shape or new_data.dtype != param.dtype:
        raise RuntimeError(
            f"nvfp4 refit re-derived {param_name} as {tuple(new_data.shape)}/{new_data.dtype}, "
            f"but the CUDA-graph live parameter is {tuple(param.shape)}/{param.dtype}"
        )
    if new_data.data_ptr() != param.data_ptr():
        param.data.copy_(new_data)
    setattr(layer, param_name, param)


def _restore_nvfp4_input_scales_in_place(module, converted):
    converted = list(converted)
    live = getattr(module, _NVFP4_LIVE_ATTR, None) or {}
    for index, name in ((3, "w13_input_scale"), (7, "w2_input_scale")):
        tensor = live.pop(name, None)
        new_data = converted[index]
        if tensor is None or new_data is None:
            continue
        if new_data.shape != tensor.shape or new_data.dtype != tensor.dtype:
            raise RuntimeError(
                f"nvfp4 refit re-derived {name} as {tuple(new_data.shape)}/{new_data.dtype}, "
                f"but the CUDA-graph live tensor is {tuple(tensor.shape)}/{tensor.dtype}"
            )
        if new_data.data_ptr() != tensor.data_ptr():
            tensor.copy_(new_data)
        converted[index] = tensor
    return tuple(converted)


def _attest_nvfp4_kernel_scale_references(module):
    """Verify that the retained CUDA-graph kernel sees the current refit scales."""
    method = module.quant_method
    kernel = method.moe_kernel
    config = method.moe_quant_config
    experts = getattr(kernel, "fused_experts", None)
    if experts is None or experts.quant_config is not config:
        raise RuntimeError("nvfp4 retained kernel no longer references its retained quant config")

    for config_name, parameter_name in (
        ("g1_alphas", "w13_weight_scale_2"),
        ("g2_alphas", "w2_weight_scale_2"),
        ("w1_scale", "w13_weight_scale"),
        ("w2_scale", "w2_weight_scale"),
    ):
        actual = getattr(config, config_name, None)
        registered = getattr(module, parameter_name, None)
        if not isinstance(actual, torch.Tensor) or not isinstance(registered, torch.Tensor):
            raise RuntimeError(f"nvfp4 kernel scale reference missing: {config_name}/{parameter_name}")
        if actual.device != registered.device or actual.data_ptr() != registered.data_ptr():
            raise RuntimeError(f"nvfp4 kernel has stale scale reference: {config_name}/{parameter_name}")

    for config_name, input_name in (("a1_gscale", "w13_input_scale"), ("a2_gscale", "w2_input_scale")):
        actual = getattr(config, config_name, None)
        input_scale = getattr(module, input_name, None)
        if not isinstance(actual, torch.Tensor) or not isinstance(input_scale, torch.Tensor):
            raise RuntimeError(f"nvfp4 activation scale reference missing: {config_name}/{input_name}")
        if not torch.equal(actual, 1.0 / input_scale):
            raise RuntimeError(f"nvfp4 {config_name} does not match the current activation scale")


def _restore_nvfp4_kernel_config_in_place(module, retained_kernel, retained_config):
    """Copy newly derived scales into the config storage captured by CUDA graphs."""
    method = module.quant_method
    processing_config = method.moe_quant_config
    for name in ("a1_gscale", "a2_gscale"):
        retained = getattr(retained_config, name, None)
        current = getattr(processing_config, name, None)
        if not isinstance(retained, torch.Tensor) or not isinstance(current, torch.Tensor):
            raise RuntimeError(f"nvfp4 refit cannot restore derived scale {name}")
        if retained.shape != current.shape or retained.dtype != current.dtype:
            raise RuntimeError(
                f"nvfp4 refit re-derived {name} as {tuple(current.shape)}/{current.dtype}, "
                f"but the CUDA-graph config has {tuple(retained.shape)}/{retained.dtype}"
            )
        retained.copy_(current)

    method.moe_kernel = retained_kernel
    method.moe_quant_config = retained_config
    _attest_nvfp4_kernel_scale_references(module)


def _process_nvfp4_moe_params(module):
    from vllm.model_executor.layers.quantization.compressed_tensors.compressed_tensors_moe import (
        compressed_tensors_moe_w4a4_nvfp4,
    )

    original_convert = compressed_tensors_moe_w4a4_nvfp4.convert_to_nvfp4_moe_kernel_format

    def convert_to_nvfp4_moe_kernel_format(*args, **kwargs):
        return _restore_nvfp4_input_scales_in_place(module, original_convert(*args, **kwargs))

    retained_kernel = module.quant_method.moe_kernel
    retained_config = module.quant_method.moe_quant_config
    with (
        patch.object(
            compressed_tensors_moe_w4a4_nvfp4,
            "replace_parameter",
            _replace_nvfp4_parameter_in_place,
        ),
        patch.object(
            compressed_tensors_moe_w4a4_nvfp4,
            "convert_to_nvfp4_moe_kernel_format",
            convert_to_nvfp4_moe_kernel_format,
        ),
    ):
        module.quant_method.process_weights_after_loading(module)
    _restore_nvfp4_kernel_config_in_place(module, retained_kernel, retained_config)
    leftover = getattr(module, _NVFP4_LIVE_ATTR, None) or {}
    delattr(module, _NVFP4_LIVE_ATTR)
    if leftover:
        raise RuntimeError(f"nvfp4 refit left {sorted(leftover)} un-reinstated")


def stage_nvfp4_moe_params_for_loading(model):
    """Stage NVFP4 W4A4 FlashInfer CUTLASS experts for a bucketed refit."""
    from vllm.model_executor.layers.fused_moe.oracle.nvfp4 import NvFp4MoeBackend

    staged = []
    for module in model.modules():
        if not _is_nvfp4_fused_moe_module(module):
            continue
        method = module.quant_method
        if method.use_a16 or method.nvfp4_backend != NvFp4MoeBackend.FLASHINFER_CUTLASS:
            raise NotImplementedError(
                "NVFP4 refit supports only W4A4 FlashInfer CUTLASS routed experts; "
                f"got use_a16={method.use_a16}, backend={method.nvfp4_backend}"
            )
        _stage_nvfp4_moe_params(module)
        staged.append(module)
    logger.info("Staged %d NVFP4 W4A4 MoE modules for in-place refit", len(staged))
    return staged


def process_nvfp4_moe_weights_after_loading(modules):
    for module in modules:
        _process_nvfp4_moe_params(module)


def _process_mxfp4_moe_params(module):
    from vllm.model_executor.layers.quantization import mxfp4 as vllm_mxfp4

    with patch.object(vllm_mxfp4, "replace_parameter", _replace_parameter_in_place):
        module.quant_method.process_weights_after_loading(module)

    # Every staged param is consumed through the patched replace_parameter, so
    # a leftover means post-processing took a path that assigns weights some
    # other way and the live storage was never refreshed.
    leftover = getattr(module, _MXFP4_LIVE_ATTR, None) or {}
    delattr(module, _MXFP4_LIVE_ATTR)
    if leftover:
        raise RuntimeError(
            f"mxfp4 refit left {sorted(leftover)} un-reinstated; every backend listed in "
            "_refittable_mxfp4_backends is expected to route each expert param through "
            "replace_parameter."
        )


def stage_mxfp4_moe_params_for_loading(model):
    """Hand ``load_weights`` checkpoint-layout expert buffers.

    Returns the staged modules for ``process_mxfp4_moe_weights_after_loading``.
    A model with no mxfp4 experts yields an empty list, which makes this safe
    to call unconditionally.
    """
    supported = _refittable_mxfp4_backends()
    staged_modules = []
    backends = set()
    for module in model.modules():
        if not _is_mxfp4_fused_moe_module(module):
            continue

        backend = getattr(module.quant_method, "mxfp4_backend", None)
        if backend not in supported:
            # Refusing beats skipping: an unsupported backend would quietly load
            # checkpoint-layout data into rewritten parameters, and the rollout
            # would drift with nothing pointing at the cause.
            raise NotImplementedError(
                f"mxfp4 MoE refit does not support the {backend} backend selected by "
                f"{type(module).__name__}. Supported backends: "
                f"{', '.join(str(b) for b in supported)}."
            )

        _stage_mxfp4_moe_params(module)
        staged_modules.append(module)
        backends.add(backend)

    logger.info(
        "Staged %d mxfp4 MoE modules for in-place refit (backends: %s)",
        len(staged_modules),
        ", ".join(sorted(str(b) for b in backends)) or "none",
    )
    return staged_modules


def process_mxfp4_moe_weights_after_loading(modules):
    """Repack the loaded experts into the kernel layout inside the live storage."""
    for module in modules:
        _process_mxfp4_moe_params(module)
