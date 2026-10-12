# Copyright 2024 Bytedance Ltd. and/or its affiliates
# Copyright (c) 2024, NVIDIA CORPORATION. All rights reserved.
# Copyright 2023-2024 SGLang Team
# Copyright 2025 ModelBest Inc. and/or its affiliates
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
"""Pretrain utilities."""

import inspect
import logging
import os
from dataclasses import dataclass
from typing import Any

import torch
from megatron.core import parallel_state
from megatron.core.distributed import DistributedDataParallel as DDP
from megatron.core.distributed import DistributedDataParallelConfig
from megatron.core.optimizer import ChainedOptimizer
from megatron.core.parallel_state import get_global_memory_buffer
from megatron.core.transformer import MLATransformerConfig, TransformerConfig
from megatron.core.transformer.module import Float16Module
from megatron.core.transformer.multi_token_prediction import MTPLossLoggingHelper
from megatron.core.utils import get_attr_wrapped_model
from transformers import PretrainedConfig

from verl.utils.device import get_device_id, get_device_name, get_torch_device
from verl.utils.fs import local_mkdir_safe
from verl.workers.config import HFModelConfig, McoreEngineConfig

logger = logging.getLogger(__file__)
logger.setLevel(os.getenv("VERL_LOGGING_LEVEL", "WARN"))


def get_model_config(model):
    return get_attr_wrapped_model(model, "config", allow_none=False)


def _assert_muon_layer_wise_ddp_supported() -> None:
    """Fail closed when Megatron-Core cannot build LayerWise DDP layouts."""
    try:
        from megatron.core.optimizer.layer_wise_optimizer import (  # noqa: F401
            LayerWiseDistributedOptimizer,
            tag_params_for_buffer_routing,
        )
    except ImportError as exc:
        raise ValueError(
            "Muon layer-wise distributed optimizer requires Megatron-Core "
            "layer_wise_optimizer support. Upgrade megatron-core or disable "
            "use_layer_wise_distributed_optimizer."
        ) from exc
    try:
        DistributedDataParallelConfig(use_layer_wise_param_layout=True)
    except TypeError as exc:
        raise ValueError(
            "Muon layer-wise distributed optimizer requires DistributedDataParallelConfig."
            "use_layer_wise_param_layout. Upgrade megatron-core or disable "
            "use_layer_wise_distributed_optimizer."
        ) from exc


def wrap_model_chunks_with_layerwise_aware_ddp(
    model_chunks,
    tfconfig,
    *,
    use_distributed_optimizer: bool = True,
    use_layer_wise_distributed_optimizer: bool = False,
    override_ddp_config: dict | None = None,
):
    """Wrap model chunks in Megatron DDP, with optional LayerWise (Muon) param layouts.

    Mirrors ``megatron.training.training.wrap_model_chunks_with_ddp`` so Muon gets
    ``tag_params_for_buffer_routing`` + ``compute_full_param_layout`` before DDP
    construction — verl's plain DDP wrap omits this and causes redundant buffers.
    """
    from megatron.core.distributed import (
        DistributedDataParallel as DDP,
    )
    from megatron.core.optimizer.layer_wise_optimizer import (
        LayerWiseDistributedOptimizer,
        tag_params_for_buffer_routing,
    )
    from megatron.core.process_groups_config import ProcessGroupCollection
    from megatron.core.utils import get_pg_size

    ddp_config_dict = {
        "use_distributed_optimizer": use_distributed_optimizer,
        "grad_reduce_in_fp32": True,
        "overlap_grad_reduce": False,
    }
    if override_ddp_config is not None:
        ddp_config_dict.update(override_ddp_config)
    ddp_config = DistributedDataParallelConfig(**ddp_config_dict)

    per_chunk_layouts = [None] * len(model_chunks)
    if use_layer_wise_distributed_optimizer:
        tag_params_for_buffer_routing(model_chunks)
        # Match Megatron training.py: LayerWise path needs DistOpt-style layout for scalar buffers.
        ddp_config.use_distributed_optimizer = True
        if ddp_config_dict.get("use_layer_wise_param_layout") is None:
            ddp_config.use_layer_wise_param_layout = True
        layout_pgs = ProcessGroupCollection.use_mpu_process_groups()
        assert layout_pgs.dp_cp is not None, "dp_cp process group required for LayerWise param layout"
        dp_size = get_pg_size(layout_pgs.dp_cp)
        expt_dp_size = get_pg_size(getattr(layout_pgs, "expt_dp", None))
        for i, chunk in enumerate(model_chunks):
            all_params = [p for p in chunk.parameters() if p.requires_grad]
            per_chunk_layouts[i] = LayerWiseDistributedOptimizer.compute_full_param_layout(
                all_params,
                ddp_config.bucket_size,
                dp_size,
                ddp_config,
                expert_data_parallel_world_size=expt_dp_size,
            )

    ddp_models = []
    for model_chunk_idx, (model_chunk, layout) in enumerate(zip(model_chunks, per_chunk_layouts, strict=True)):
        chunk_kwargs = {}
        if layout is not None:
            chunk_kwargs["full_param_layout"] = layout
        ddp_models.append(
            DDP(
                config=tfconfig,
                module=model_chunk,
                disable_bucketing=(model_chunk_idx > 0),
                ddp_config=ddp_config,
                **chunk_kwargs,
            )
        )
    for model_module in ddp_models:
        model_module.broadcast_params()
    return ddp_models


_HF_CONFIG_CHILD_NAMES = ("text_config", "language_config", "thinker_config", "model_config")


def _get_hf_text_config(hf_config: PretrainedConfig):
    get_text_config = getattr(hf_config, "get_text_config", None)
    if callable(get_text_config):
        text_config = get_text_config()
        if text_config is not None:
            return text_config
    return getattr(hf_config, "text_config", None)


def _iter_hf_config_tree(hf_config: PretrainedConfig):
    seen = set()

    def _visit(config):
        if id(config) in seen:
            return
        seen.add(id(config))

        # Visit the canonical text config and known language-model wrappers before
        # the composite root. Never walk arbitrary sub_configs: audio/code2wav
        # siblings can expose conflicting model attributes.
        text_config = _get_hf_text_config(config)
        if text_config is not None and text_config is not config:
            yield from _visit(text_config)

        for child_name in _HF_CONFIG_CHILD_NAMES:
            child_config = getattr(config, child_name, None)
            if child_config is not None and child_config is not text_config:
                yield from _visit(child_config)
        yield config

    yield from _visit(hf_config)


def get_hf_config_attr(hf_config: PretrainedConfig, attr_name: str) -> Any:
    """Find an attribute in a nested Hugging Face model configuration."""
    text_config = _get_hf_text_config(hf_config)
    if text_config is not None:
        value = getattr(text_config, attr_name, None)
        if value is not None:
            return value

    for config in _iter_hf_config_tree(hf_config):
        value = getattr(config, attr_name, None)
        if value is not None:
            return value
    raise AttributeError(f"{type(hf_config).__name__} has no nested {attr_name}.")


def get_hf_rope_theta(hf_config: PretrainedConfig) -> float:
    """Return RoPE base frequency theta.

    Most configs expose ``rope_theta`` on the root. Newer models (e.g. Qwen3 in transformers>=5) store it under
    ``rope_parameters["rope_theta"]``, optionally nested per attention pattern when ``rope_parameters`` maps names
    to parameter dicts.
    """

    def _maybe_get_theta(config: Any) -> float | None:
        theta = getattr(config, "rope_theta", None)
        if theta is not None:
            return theta

        rope_parameters = getattr(config, "rope_parameters", None)
        if isinstance(rope_parameters, dict):
            if "rope_theta" in rope_parameters:
                return rope_parameters["rope_theta"]
            for value in rope_parameters.values():
                if isinstance(value, dict) and "rope_theta" in value:
                    return value["rope_theta"]
        return None

    for config in _iter_hf_config_tree(hf_config):
        theta = _maybe_get_theta(config)
        if theta is not None:
            return theta

    raise AttributeError(
        f"{type(hf_config).__name__} has no rope_theta and no rope_parameters['rope_theta'] — "
        "cannot determine RoPE base."
    )


@dataclass
class McoreModuleWrapperConfig:
    """Configuration for Mcore module wrapper."""

    is_value_model: bool = False
    wrap_with_ddp: bool = True
    use_distributed_optimizer: bool = True
    use_layer_wise_distributed_optimizer: bool = False
    use_megatron_fsdp: bool = False


def make_megatron_module(
    wrap_config: McoreModuleWrapperConfig,
    hf_config: PretrainedConfig,
    bridge: Any = None,
    provider: Any = None,
    override_model_config: dict[str, Any] = None,
    override_ddp_config: dict[str, Any] = None,
    peft_cls: Any = None,
    peft_config: Any = None,
):
    try:
        hf_config.rope_theta = get_hf_rope_theta(hf_config)
    except AttributeError:
        # NoPE / hybrid-SSM configs (e.g. NemotronH) carry no rope at all; the
        # provider/bridge owns rotary setup, so absence is not an error here.
        pass

    if override_model_config is None:
        override_model_config = {}

    if bridge is None or provider is None:
        raise ValueError("Megatron-Bridge and its model provider are required")

    from verl.models.mcore.bridge import freeze_moe_router, make_value_model

    hidden_size = get_hf_config_attr(hf_config, "hidden_size")
    value_model_hook = make_value_model(hidden_size, provider.sequence_parallel)
    post_model_creation_callbacks = []
    if wrap_config.is_value_model:
        post_model_creation_callbacks.append(value_model_hook)
    if override_model_config.get("moe_config", {}).get("freeze_moe_router", False):
        post_model_creation_callbacks.append(freeze_moe_router)

    # When using PEFT with Megatron-Bridge, we must apply PEFT transformation
    # BEFORE wrapping the model in DDP. This is required because:
    # 1. PEFT freezes base model parameters (requires_grad=False)
    # 2. DDP must be aware of which parameters are trainable when building gradient buckets
    # 3. The distributed optimizer must only track trainable (adapter) parameters
    # See Megatron-Bridge docs: training/peft.md

    # Register PEFT transformation as pre-wrap hook if peft_cls is specified
    # This must happen BEFORE DDP wrapping to avoid KeyError with frozen parameters
    if peft_cls is not None:
        from megatron.bridge.peft.utils import create_peft_hook, load_peft_adapter_checkpoint

        from verl.utils.megatron_peft_utils import print_adapter_info

        provider.register_pre_wrap_hook(create_peft_hook(peft_cls, training=True))

        adapter_path = peft_config.get("adapter_path", None)
        if adapter_path:

            def adapter_checkpoint_hook(model):
                print(f"Loading adapter weights from: {adapter_path}")
                load_peft_adapter_checkpoint(
                    model,
                    adapter_path,
                    peft=peft_cls,
                    strict=False,
                )
                return model

            provider.register_pre_wrap_hook(adapter_checkpoint_hook)

        def peft_info_hook(model):
            if torch.distributed.get_rank() == 0:
                print_adapter_info(model)
            return model

        provider.register_pre_wrap_hook(peft_info_hook)

    # Register post-creation callbacks (make_value_model, freeze_moe_router) as pre-wrap hooks
    for callback in post_model_creation_callbacks:
        provider.register_pre_wrap_hook(callback)

    layer_wise_ddp = wrap_config.wrap_with_ddp and wrap_config.use_layer_wise_distributed_optimizer
    if layer_wise_ddp:
        if wrap_config.use_megatron_fsdp:
            raise ValueError(
                "Muon layer-wise distributed optimizer is incompatible with Megatron FSDP. "
                "Set use_megatron_fsdp=False or disable use_layer_wise_distributed_optimizer."
            )
        _assert_muon_layer_wise_ddp_supported()

    # Create DDP config if needed

    # Megatron-Bridge >= v0.5.0 provides apply_overrides_and_finalize.
    # Megatron-Bridge <  v0.5.0 does not, so we fall back to manual setattr + finalize.
    try:
        from megatron.bridge.training.utils.config_utils import create_ddp_config

        ddp_config = create_ddp_config(
            wrap_with_ddp=wrap_config.wrap_with_ddp and not layer_wise_ddp,
            use_distributed_optimizer=wrap_config.use_distributed_optimizer,
            use_megatron_fsdp=wrap_config.use_megatron_fsdp,
            overrides=override_ddp_config,
        )
    except ImportError:
        ddp_config = None
        if wrap_config.wrap_with_ddp and not layer_wise_ddp:
            from megatron.bridge.training.config import DistributedDataParallelConfig

            ddp_config_dict = {
                "use_distributed_optimizer": wrap_config.use_distributed_optimizer,
            }
            if wrap_config.use_megatron_fsdp:
                ddp_config_dict["use_distributed_optimizer"] = True
                ddp_config_dict.setdefault("check_for_nan_in_grad", True)
                ddp_config_dict.setdefault("use_megatron_fsdp", True)
                ddp_config_dict.setdefault("data_parallel_sharding_strategy", "optim_grads_params")
                ddp_config_dict.setdefault("overlap_grad_reduce", True)
            if override_ddp_config is not None:
                ddp_config_dict.update(override_ddp_config)
            ddp_config = DistributedDataParallelConfig(**ddp_config_dict)
            ddp_config.finalize()

    # Now call provide_distributed_model with all hooks registered
    # Hooks will be applied automatically before DDP wrapping
    model = provider.provide_distributed_model(
        wrap_with_ddp=wrap_config.wrap_with_ddp and not layer_wise_ddp,
        ddp_config=ddp_config,
        fp16=provider.fp16,
        bf16=provider.bf16,
        use_megatron_fsdp=wrap_config.use_megatron_fsdp,
    )

    if layer_wise_ddp:
        if not isinstance(model, list):
            model = [model]
        bridge_tf_config = get_model_config(model[0])
        model = wrap_model_chunks_with_layerwise_aware_ddp(
            model,
            bridge_tf_config,
            use_distributed_optimizer=wrap_config.use_distributed_optimizer,
            use_layer_wise_distributed_optimizer=True,
            override_ddp_config=override_ddp_config,
        )

    # Extract TransformerConfig from the created model
    tf_config = get_model_config(model[0] if isinstance(model, list) else model)
    if isinstance(tf_config, MLATransformerConfig):
        # Apply MLA compatibility patches after model creation.
        from verl.models.mcore.patch import apply_patch

        apply_patch()
    return model, tf_config


try:
    from megatron.core.distributed.fsdp.mcore_fsdp_adapter import FullyShardedDataParallel as _MegatronFSDP
    from megatron.core.distributed.fsdp.src.megatron_fsdp.megatron_fsdp import MegatronFSDP

    ALL_MODULE_WRAPPER_CLASSNAMES = (DDP, Float16Module, _MegatronFSDP, MegatronFSDP)
except ImportError:
    ALL_MODULE_WRAPPER_CLASSNAMES = (DDP, Float16Module)


def unwrap_model(model, module_instances=ALL_MODULE_WRAPPER_CLASSNAMES):
    return_list = True
    if not isinstance(model, list):
        model = [model]
        return_list = False
    unwrapped_model = []
    for model_module in model:
        while isinstance(model_module, module_instances):
            model_module = model_module.module
        unwrapped_model.append(model_module)
    if not return_list:
        return unwrapped_model[0]
    return unwrapped_model


def _can_safely_resize_storage(tensor: torch.Tensor) -> bool:
    """Check whether it is safe to call ``storage().resize_(0)`` on *tensor*.

    Resizing the underlying storage to zero immediately frees the GPU memory
    but also invalidates **every** tensor that shares the same storage
    (e.g. views, tied weights stored as different Python objects, or slices
    of a DDP flat buffer).  This function returns True only when the tensor
    exclusively owns its entire storage, making ``resize_(0)`` safe.
    """
    return (
        # Storage holds exactly the elements of this tensor – no room for
        # other tensors sharing the same storage.
        tensor.storage().size() == tensor.numel()
        # Tensor starts at the beginning of the storage – not a slice/view
        # offset into a larger buffer.
        and tensor.storage_offset() == 0
        # Tensor is contiguous in memory – rules out transposed or
        # non-contiguous views that only occupy part of the storage layout.
        and tensor.is_contiguous()
    )


def _clear_te_fp8_weight_workspaces(model_chunk):
    """Clear cached Transformer-Engine FP8 weight workspaces on a model chunk.

    When training with an FP8 param dtype (or loading a native-FP8 checkpoint),
    Transformer-Engine ``Linear`` / ``GroupedLinear`` layers cache quantized
    (``Float8Tensor`` / ``Float8BlockwiseQTensor``) copies of their weights in
    ``module._fp8_workspaces`` (keyed ``weight``, ``weight0..weightN``). These
    caches are plain tensors, not ``nn.Parameter``s or registered buffers, so the
    parameter/buffer offloading in :func:`offload_megatron_model_to_cpu` never
    frees them and they stay resident on the GPU -- for large MoE checkpoints this
    can be tens of GiB per rank that defeats the offload. Transformer-Engine lazily
    rebuilds the workspace on the next forward, so dropping it here is safe. This is
    a no-op for bf16/fp16 models (the attribute is absent or empty).

    Returns the number of cached workspace entries cleared.
    """
    cleared = 0
    for submodule in model_chunk.modules():
        workspaces = getattr(submodule, "_fp8_workspaces", None)
        if isinstance(workspaces, dict) and workspaces:
            cleared += len(workspaces)
            workspaces.clear()
    return cleared


@torch.no_grad()
def offload_megatron_model_to_cpu(models):
    """
    In megatron, the model and optimizer storage are:
    - bf16 parameter data chunked in model parallel group
    - fp32 grad chunked in model parallel group
    - fp32 main_parameter chunked in model and dp group
    - fp32 optimizer state chunked in model and dp group
    """
    for model_chunk in models:
        if isinstance(model_chunk, DDP):
            model_chunk_all_buffers = [model_chunk.buffers, model_chunk.expert_parallel_buffers]
            for buffers in model_chunk_all_buffers:
                for buffer in buffers:
                    # offload parameters
                    if buffer.param_data.storage().size() > 0:
                        # Reuse a single pinned cpu_data buffer per DDP buffer.
                        # The previous implementation reallocated cpu_data via
                        # `.cpu().pin_memory()` on every offload. Python evaluates
                        # the RHS before the assignment, so the new pinned block is
                        # allocated while the old cpu_data is still referenced --
                        # peak host memory at the moment of allocation is 2x
                        # param_data size. On large Megatron models this transient
                        # peak exceeds the cgroup limit and OOMKills the pod even
                        # though steady-state usage would be 1x. Reallocating here
                        # would re-trigger the same 2x peak, so we allocate at most
                        # once per buffer and assert shape/dtype invariance on
                        # subsequent calls -- a mismatch means a caller rebuilt
                        # param_data under us, which is a bug we want surfaced
                        # rather than silently worked around.
                        existing = getattr(buffer.param_data, "cpu_data", None)
                        if existing is None:
                            buffer.param_data.cpu_data = torch.empty(
                                buffer.param_data.size(),
                                dtype=buffer.param_data.dtype,
                                device="cpu",
                                pin_memory=True,
                            )
                            buffer.param_data_size = buffer.param_data.storage().size()
                        else:
                            assert existing.shape == buffer.param_data.shape, (
                                f"cpu_data shape {tuple(existing.shape)} != "
                                f"param_data shape {tuple(buffer.param_data.shape)}; "
                                "reallocating would reintroduce the 2x peak."
                            )
                            assert existing.dtype == buffer.param_data.dtype, (
                                f"cpu_data dtype {existing.dtype} != "
                                f"param_data dtype {buffer.param_data.dtype}; "
                                "reallocating would reintroduce the 2x peak."
                            )
                        # Synchronous D2H copy into the preexisting pinned
                        # buffer; must complete before resize_(0) frees the
                        # GPU storage.
                        buffer.param_data.cpu_data.copy_(buffer.param_data.data, non_blocking=False)
                        buffer.param_data.storage().resize_(0)

                    assert buffer.param_data_size == buffer.param_data.cpu_data.storage().size()

                    if buffer.grad_data.storage().size() > 0:
                        # if the grad_data size is already zero, we assume that it is already offloaded
                        buffer.grad_data_size = buffer.grad_data.storage().size()
                        buffer.grad_data.storage().resize_(0)
            # Offload frozen parameters not in DDP buffers (e.g. base model in LoRA/PEFT)
            # DDP buffers only contain requires_grad=True params, so frozen params must be offloaded separately.
            for param in model_chunk.module.parameters():
                if not param.requires_grad and param.device.type != "cpu":
                    param.data = param.data.to("cpu", non_blocking=True)
        else:
            # we need this for ref module
            for _, param in model_chunk.named_parameters():
                old_data = param.data
                param.data = param.data.to("cpu")
                if _can_safely_resize_storage(old_data):
                    old_data.storage().resize_(0)
                if param.grad is not None:
                    old_grad = param.grad
                    param.grad = param.grad.to("cpu")
                    if _can_safely_resize_storage(old_grad):
                        old_grad.storage().resize_(0)

        # Drop Transformer-Engine FP8 weight-workspace caches, which hold quantized
        # copies of the weights on GPU and are not covered by the parameter offload above.
        cleared = _clear_te_fp8_weight_workspaces(model_chunk)
        if cleared:
            logger.debug("Cleared %d TE FP8 weight workspaces on offload", cleared)

    get_torch_device().empty_cache()


@torch.no_grad()
def load_megatron_model_to_gpu(models, load_grad=True, load_frozen_params=True):
    """
    Load megatron model to GPU.
    Args:
        models: The model to load.
        load_grad: Whether to load gradients.
        load_frozen_params: Whether to load frozen parameters.
    """
    for model_chunk in models:
        if isinstance(model_chunk, DDP):
            model_chunk_all_buffers = [model_chunk.buffers, model_chunk.expert_parallel_buffers]
            for buffers in model_chunk_all_buffers:
                for buffer in buffers:
                    # sometimes, we don't want to load grad for pure inference
                    if load_grad and hasattr(buffer, "grad_data_size"):
                        current_storage_size = buffer.grad_data.storage().size()
                        if current_storage_size == 0 or current_storage_size == buffer.grad_data_size:
                            buffer.grad_data.storage().resize_(buffer.grad_data_size)
                            buffer.grad_data.zero_()
                        else:
                            # Non-standard layers (e.g. GatedDeltaNet) may have grad
                            # buffers with mismatched storage size; skip resize and
                            # zero in-place with current storage.
                            buffer.grad_data.zero_()

                    if buffer.param_data.storage().size() == 0:
                        buffer.param_data.storage().resize_(buffer.param_data_size)
                        # copy data from cpu to cuda
                        buffer.param_data.copy_(buffer.param_data.cpu_data, non_blocking=True)

            # Load frozen parameters that were offloaded (e.g. base model in LoRA/PEFT)
            if load_frozen_params:
                device_id = get_device_id()
                for param in model_chunk.module.parameters():
                    if not param.requires_grad and param.device.type == "cpu":
                        param.data = param.data.to(device_id, non_blocking=True)
        else:
            # we need this for ref module
            device_id = get_device_id()
            for _, param in model_chunk.named_parameters():
                param.data = param.data.to(device_id, non_blocking=True)
                if param.grad is not None:
                    param.grad = param.grad.to(device_id, non_blocking=True)
    get_torch_device().empty_cache()


@torch.no_grad()
def offload_megatron_copy_params(optimizers):
    """
    Offload optimizer parameters to CPU. Supports both Megatron optimizers
    and `ChainedOptimizer`, which wraps a list of underlying optimizers.

    Args:
        optimizers: The optimizer or ChainedOptimizer instance.
    """

    def _iter_opts(opt):
        if isinstance(opt, ChainedOptimizer):
            return opt.chained_optimizers
        return [opt]

    def offload_tensor_to_cpu(tensor):
        if tensor is None:
            return
        tensor.data = tensor.data.to("cpu", non_blocking=True)

    def offload_group_to_cpu(group):
        if group is None:
            return

        if isinstance(group, list):
            for param_group in group:
                if isinstance(param_group, list):
                    for param in param_group:
                        offload_tensor_to_cpu(param)
                else:
                    offload_tensor_to_cpu(param_group)
        else:
            offload_tensor_to_cpu(group)

    # Offload all parameter groups to CPU for each underlying optimizer

    for _opt in _iter_opts(optimizers):
        if hasattr(_opt, "shard_fp32_from_float16_groups"):
            offload_group_to_cpu(_opt.shard_fp32_from_float16_groups)


@torch.no_grad()
def load_megatron_copy_params(optimizers):
    """
    Load optimizer parameters back to GPU. Handles ChainedOptimizer.

    Args:
        optimizers: Optimizer or ChainedOptimizer instance.
    """

    def _iter_opts(opt):
        if isinstance(opt, ChainedOptimizer):
            return opt.chained_optimizers
        return [opt]

    def load_tensor_to_gpu(tensor):
        if tensor is None:
            return
        device_id = get_device_id()
        tensor.data = tensor.data.to(device_id, non_blocking=True)

    def load_group_to_gpu(group):
        if group is None:
            return

        if isinstance(group, list):
            for param_group in group:
                if isinstance(param_group, list):
                    for param in param_group:
                        load_tensor_to_gpu(param)
                else:
                    load_tensor_to_gpu(param_group)
        else:
            load_tensor_to_gpu(group)

    # Load all parameter groups to GPU for each underlying optimizer

    for _opt in _iter_opts(optimizers):
        if hasattr(_opt, "shard_fp32_from_float16_groups"):
            load_group_to_gpu(_opt.shard_fp32_from_float16_groups)


@torch.no_grad()
def offload_megatron_optimizer(optimizers):
    def _iter_opts(opt):
        if isinstance(opt, ChainedOptimizer):
            return opt.chained_optimizers
        return [opt]

    for _opt in _iter_opts(optimizers):
        offload_megatron_copy_params(_opt)
        ## worker may hold zero parameter when enabling custom pipeline layout
        if _opt.optimizer is not None:
            # HybridDeviceOptimizer: offload all sub-optimizer states to CPU
            # TODO: this should be a method in Megatron-LM's HybridDeviceOptimizer
            hdo = _opt.optimizer
            if all(hasattr(hdo, attr) for attr in ("sub_optimizers", "inner_param_to_orig_param", "state")):
                for optimizer in hdo.sub_optimizers:
                    for param, state in optimizer.state.items():
                        for k, v in state.items():
                            if not isinstance(v, torch.Tensor):
                                continue
                            orig_param = hdo.inner_param_to_orig_param.get(param, param)
                            hdo.state[orig_param][k] = state[k] = v.to("cpu")
            else:
                opt_state_dict_values = _opt.optimizer.state.values()
                for v in opt_state_dict_values:
                    if "exp_avg" in v:
                        v["exp_avg"] = v["exp_avg"].to("cpu", non_blocking=True)
                    if "exp_avg_sq" in v:
                        v["exp_avg_sq"] = v["exp_avg_sq"].to("cpu", non_blocking=True)
                    # Offload additional optimizer state that is stored under
                    # "master_param" when use_precision_aware_optimizer=True.
                    if "master_param" in v:
                        v["master_param"] = v["master_param"].to("cpu", non_blocking=True)

        try:
            # Free TransformerEngine's dummy weight gradients cache
            # https://github.com/NVIDIA/TransformerEngine/blob/release_v2.10/transformer_engine/pytorch/module/base.py#L64
            from transformer_engine.pytorch.module.base import _dummy_wgrads

            _dummy_wgrads.clear()
        except ImportError:
            pass

        # Free Megatron-LM's global memory buffer
        get_global_memory_buffer().buffer.clear()

        get_torch_device().empty_cache()


@torch.no_grad()
def load_megatron_optimizer(optimizers):
    def _iter_opts(opt):
        if isinstance(opt, ChainedOptimizer):
            return opt.chained_optimizers
        return [opt]

    for _opt in _iter_opts(optimizers):
        load_megatron_copy_params(_opt)
        ## worker may hold zero parameter when enabling custom pipeline layout
        if _opt.optimizer is not None:
            # if we are using HybridDeviceOptimizer, we need to only move gpu optimizer state to gpu
            if hasattr(_opt.optimizer, "_move_new_state_to_right_device"):
                _opt.optimizer._move_new_state_to_right_device()
            else:
                opt_state_dict_values = _opt.optimizer.state.values()
                for v in opt_state_dict_values:
                    if "exp_avg" in v:
                        v["exp_avg"] = v["exp_avg"].to(get_device_id(), non_blocking=True)
                    if "exp_avg_sq" in v:
                        v["exp_avg_sq"] = v["exp_avg_sq"].to(get_device_id(), non_blocking=True)
                    # Load additional optimizer state that is stored under
                    # "master_param" when use_precision_aware_optimizer=True.
                    if "master_param" in v:
                        v["master_param"] = v["master_param"].to(get_device_id(), non_blocking=True)
        get_torch_device().empty_cache()


# ---------------------------------------------------------------------------
# Megatron checkpoint layout
# ---------------------------------------------------------------------------
#
# Each Megatron checkpoint directory (``local_path``) has the following shape::
#
#     local_path/
#     ├── ckpt_contents.json           # manifest (authoritative mapping)
#     ├── transformer_config.json      # rank-0, when 'extra' is saved
#     ├── model/
#     │   ├── huggingface/             # Megatron-Bridge HF weights + config + tokenizer
#     │   └── dist_ckpt/               # Megatron sharded model or PEFT adapter shards
#     ├── optimizer/
#     │   └── dist_ckpt/               # optimizer state + lr_scheduler
#     └── extra/
#         └── dist_ckpt/               # rng_state
#
# All helpers below return the canonical path for a given component.  They
# do not check whether the directory contains data — callers decide whether
# to read it based on the manifest / save_contents.


_MODEL_SUBDIR = "model"
_OPTIMIZER_SUBDIR = "optimizer"
_EXTRA_SUBDIR = "extra"
_DIST_CKPT_SUBDIR = "dist_ckpt"
_HUGGINGFACE_SUBDIR = "huggingface"


def get_model_checkpoint_path(checkpoint_path):
    """Directory holding model-weight artifacts (HF and/or Megatron shards)."""
    local_mkdir_safe(checkpoint_path)
    p = os.path.join(checkpoint_path, _MODEL_SUBDIR)
    local_mkdir_safe(p)
    return p


def get_optimizer_checkpoint_path(checkpoint_path):
    """Directory holding optimizer + lr_scheduler dist_checkpointing shards."""
    local_mkdir_safe(checkpoint_path)
    p = os.path.join(checkpoint_path, _OPTIMIZER_SUBDIR)
    local_mkdir_safe(p)
    return p


def get_extra_checkpoint_path(checkpoint_path):
    """Directory holding 'extra' artifacts (rng_state)."""
    local_mkdir_safe(checkpoint_path)
    p = os.path.join(checkpoint_path, _EXTRA_SUBDIR)
    local_mkdir_safe(p)
    return p


def get_model_dist_checkpoint_path(checkpoint_path):
    """``model/dist_ckpt/`` — Megatron model or PEFT adapter shards."""
    p = os.path.join(get_model_checkpoint_path(checkpoint_path), _DIST_CKPT_SUBDIR)
    local_mkdir_safe(p)
    return p


def get_optimizer_dist_checkpoint_path(checkpoint_path):
    """``optimizer/dist_ckpt/`` — optimizer + lr_scheduler dist_checkpointing directory."""
    p = os.path.join(get_optimizer_checkpoint_path(checkpoint_path), _DIST_CKPT_SUBDIR)
    local_mkdir_safe(p)
    return p


def get_extra_dist_checkpoint_path(checkpoint_path):
    """``extra/dist_ckpt/`` — rng_state dist_checkpointing directory."""
    p = os.path.join(get_extra_checkpoint_path(checkpoint_path), _DIST_CKPT_SUBDIR)
    local_mkdir_safe(p)
    return p


def get_hf_model_checkpoint_path(checkpoint_path):
    """``model/huggingface/`` — HuggingFace-format weights, config, and tokenizer.

    Historically this lived at ``<checkpoint>/huggingface``; as of layout
    schema v2 it is nested under ``model/``.  See
    :py:func:`verl.utils.checkpoint.megatron_checkpoint_manager.MegatronCheckpointManager._raise_for_old_layout`
    for old-layout detection.
    """
    p = os.path.join(get_model_checkpoint_path(checkpoint_path), _HUGGINGFACE_SUBDIR)
    local_mkdir_safe(p)
    return p


def get_transformer_config_checkpoint_path(checkpoint_path):
    """``transformer_config.json`` at the checkpoint root (written by rank 0)."""
    os.makedirs(checkpoint_path, exist_ok=True)
    return os.path.join(checkpoint_path, "transformer_config.json")


def get_checkpoint_contents_manifest_path(checkpoint_path):
    """Path to the ``ckpt_contents.json`` manifest describing saved contents.

    The manifest is a human- and tool-readable mapping from logical content
    (e.g. ``model``, ``optimizer``, ``hf_model``) to its on-disk location
    inside ``checkpoint_path``.  Users looking for a specific artifact in a
    Megatron checkpoint should consult this file first — see
    ``docs/advance/checkpoint.rst`` ("Locating saved contents") for the
    schema, and
    :py:meth:`verl.utils.checkpoint.megatron_checkpoint_manager.MegatronCheckpointManager._build_checkpoint_manifest`
    for the implementation.
    """
    os.makedirs(checkpoint_path, exist_ok=True)
    return os.path.join(checkpoint_path, "ckpt_contents.json")


# --- Legacy (pre-v2) helpers ------------------------------------------------
#
# Old layouts put ``dist_ckpt/`` and ``huggingface/`` directly at the
# checkpoint root.  These helpers are retained **only** so that the
# migration script (``scripts/migrate_megatron_checkpoint_layout.py``) and
# the old-layout detector can address those paths without hardcoding
# literals.  New code must not call them.


def get_legacy_dist_checkpoint_path(checkpoint_path):
    return os.path.join(checkpoint_path, _DIST_CKPT_SUBDIR)


def get_legacy_hf_model_checkpoint_path(checkpoint_path):
    return os.path.join(checkpoint_path, _HUGGINGFACE_SUBDIR)


def get_dist_checkpoint_path(checkpoint_path):  # pragma: no cover - back-compat shim
    """Deprecated — kept only so stale imports fail loudly via the layout detector.

    In the v2 layout there is no longer a single ``dist_ckpt/`` directory;
    optimizer, extra, and (optionally) model live in separate subtrees.
    Use the explicit ``get_{model,optimizer,extra}_dist_checkpoint_path``
    helpers instead.
    """
    raise RuntimeError(
        "get_dist_checkpoint_path is deprecated. The Megatron checkpoint layout "
        "now splits optimizer/extra/(model) into separate directories. Use the "
        "explicit helpers: get_model_dist_checkpoint_path, "
        "get_optimizer_dist_checkpoint_path, get_extra_dist_checkpoint_path. "
        "To migrate an old checkpoint, run scripts/migrate_megatron_checkpoint_layout.py."
    )


def get_transformer_layer_offset(pipeline_rank, vp_stage, config: TransformerConfig):
    """
    Get the index offset of any pipeline stage, given the level of pipelining.

    Make pipeline_rank and vp_stage as two arguments to make it more flexible,
    which is able to fetch layer offset for any pipeline stage.
    The original function only returns the layer offset for current pipeline stage.

    Extension to https://github.com/NVIDIA/Megatron-LM/blob/main/megatron/core/transformer/transformer_layer.py::get_transformer_layer_offset
    """

    has_vp_stage = (
        inspect.signature(parallel_state.is_pipeline_first_stage).parameters.get("vp_stage", None) is not None
    )
    extra_kwargs = {} if not has_vp_stage else {"ignore_virtual": False, "vp_stage": vp_stage}

    if config.pipeline_model_parallel_size > 1:
        if hasattr(config, "pipeline_model_parallel_layout") and config.pipeline_model_parallel_layout:
            from megatron.core.transformer.enums import LayerType

            offset = config.pipeline_model_parallel_layout.get_layer_offset(
                layer_type=LayerType.decoder, vp_stage=vp_stage
            )
        elif (
            config.num_layers_in_first_pipeline_stage is not None
            or config.num_layers_in_last_pipeline_stage is not None
        ):
            # Calculate number of pipeline stages to distribute the remaining Transformer
            # layers after deducting the Transformer layers in the first or the last stages
            middle_pipeline_stages = config.pipeline_model_parallel_size
            middle_pipeline_stages -= sum(
                [
                    1 if x is not None else 0
                    for x in (
                        config.num_layers_in_first_pipeline_stage,
                        config.num_layers_in_last_pipeline_stage,
                    )
                ]
            )

            # Calculate layers to distribute in each pipeline stage. If the
            # num_layers_in_first_pipeline_stage and num_layers_in_last_pipeline_stage
            # are not set, we will not enable uneven pipeline. All layers will be treated
            # as middle layers.
            num_layers_in_first_pipeline_stage = (
                0 if config.num_layers_in_first_pipeline_stage is None else config.num_layers_in_first_pipeline_stage
            )
            num_layers_in_last_pipeline_stage = (
                0 if config.num_layers_in_last_pipeline_stage is None else config.num_layers_in_last_pipeline_stage
            )

            middle_num_layers = (
                config.num_layers - num_layers_in_first_pipeline_stage - num_layers_in_last_pipeline_stage
            )

            if (vp_size := config.virtual_pipeline_model_parallel_size) is not None:
                assert vp_stage is not None, "vp_stage must be provided if virtual pipeline model parallel size is set"

                # Calculate number of layers in each virtual model chunk
                # If the num_layers_in_first_pipeline_stage and
                # num_layers_in_last_pipeline_stage are not set, all pipeline stages
                # will be treated as middle pipeline stages in the calculation
                num_layers_per_virtual_model_chunk_in_first_pipeline_stage = (
                    0
                    if config.num_layers_in_first_pipeline_stage is None
                    else config.num_layers_in_first_pipeline_stage // vp_size
                )

                num_layers_per_virtual_model_chunk_in_last_pipeline_stage = (
                    0
                    if config.num_layers_in_last_pipeline_stage is None
                    else config.num_layers_in_last_pipeline_stage // vp_size
                )

                num_layers_per_vritual_model_chunk_in_middle_pipeline_stage = middle_num_layers // vp_size

                # First stage + middle stage + last stage
                total_virtual_chunks = (
                    num_layers_per_virtual_model_chunk_in_first_pipeline_stage
                    + num_layers_per_vritual_model_chunk_in_middle_pipeline_stage
                    + num_layers_per_virtual_model_chunk_in_last_pipeline_stage
                )

                # Calculate the layer offset with interleaved uneven pipeline parallelism
                if pipeline_rank == 0:
                    offset = vp_stage * total_virtual_chunks
                else:
                    offset = (
                        vp_stage * total_virtual_chunks
                        + num_layers_per_virtual_model_chunk_in_first_pipeline_stage
                        + (pipeline_rank - 1)
                        * (num_layers_per_vritual_model_chunk_in_middle_pipeline_stage // middle_pipeline_stages)
                    )
            else:
                if middle_pipeline_stages > 0:
                    num_layers_per_pipeline_rank = middle_num_layers // middle_pipeline_stages
                else:
                    num_layers_per_pipeline_rank = 0

                middle_pipeline_rank = (
                    pipeline_rank if config.num_layers_in_first_pipeline_stage is None else pipeline_rank - 1
                )

                if pipeline_rank == 0:
                    offset = 0
                else:
                    offset = (middle_pipeline_rank * num_layers_per_pipeline_rank) + num_layers_in_first_pipeline_stage
        else:
            num_layers = config.num_layers

            # Increase the number of layers by one if we include the embedding (loss)
            # layer into pipeline parallelism partition and placement
            if config.account_for_embedding_in_pipeline_split:
                num_layers += 1

            if config.account_for_loss_in_pipeline_split:
                num_layers += 1

            num_layers_per_pipeline_rank = num_layers // config.pipeline_model_parallel_size

            if (vp_size := config.virtual_pipeline_model_parallel_size) is not None:
                assert vp_stage is not None, "vp_stage must be provided if virtual pipeline model parallel size is set"

                num_layers_per_virtual_rank = num_layers_per_pipeline_rank // vp_size
                total_virtual_chunks = num_layers // vp_size
                offset = vp_stage * total_virtual_chunks + (pipeline_rank * num_layers_per_virtual_rank)

                # Reduce the offset of embedding layer from the total layer number
                if config.account_for_embedding_in_pipeline_split and not parallel_state.is_pipeline_first_stage(
                    **extra_kwargs
                ):
                    offset -= 1
            else:
                offset = pipeline_rank * num_layers_per_pipeline_rank

                # Reduce the offset of embedding layer from the total layer number
                if config.account_for_embedding_in_pipeline_split and not parallel_state.is_pipeline_first_stage(
                    **extra_kwargs
                ):
                    offset -= 1
    else:
        offset = 0
    return offset


def register_megatron_training_hooks(model: list[torch.nn.Module], optimizer):
    from megatron.core.distributed import finalize_model_grads
    from megatron.core.utils import get_model_config

    try:
        from megatron.core.distributed.fsdp.mcore_fsdp_adapter import FullyShardedDataParallel as megatron_FSDP
    except ImportError:
        megatron_FSDP = DDP

    # register some callbacks for megatron training, following https://github.com/NVIDIA/Megatron-LM/blob/core_v0.15.0rc7/megatron/training/training.py#L2039-L2057
    for one_model in model:
        config = get_model_config(one_model)
        config.grad_scale_func = optimizer.scale_loss
        config.finalize_model_grads_func = finalize_model_grads

        overlap_param_gather = getattr(optimizer.config, "overlap_param_gather", False)
        overlap_grad_reduce = getattr(one_model.ddp_config, "overlap_grad_reduce", False)
        align_grad_reduce = True  # default to True, seldom to be false
        align_param_gather = getattr(one_model.ddp_config, "align_param_gather", False)

        if isinstance(model[0], megatron_FSDP | DDP) and overlap_grad_reduce:
            assert config.no_sync_func is None, (
                "When overlap_grad_reduce is True, config.no_sync_func must be None; "
                "a custom no_sync_func is not supported when overlapping grad-reduce"
            )
            config.no_sync_func = [model_chunk.no_sync for model_chunk in model]
            if len(model) == 1:
                config.no_sync_func = config.no_sync_func[0]
            if align_grad_reduce:
                config.grad_sync_func = [model_chunk.start_grad_sync for model_chunk in model]
                if len(model) == 1:
                    config.grad_sync_func = config.grad_sync_func[0]
        if overlap_param_gather and align_param_gather:
            config.param_sync_func = [model_chunk.start_param_sync for model_chunk in model]
            if len(model) == 1:
                config.param_sync_func = config.param_sync_func[0]


def mapping_string_to_attn_backend(args: dict) -> dict:
    if "attention_backend" in args and isinstance(args["attention_backend"], str):
        from megatron.core.transformer.enums import AttnBackend

        args["attention_backend"] = AttnBackend[args["attention_backend"]]
    return args


def get_megatron_mtp_loss(n_micro_batch):
    # Newer MCore tracks raw loss sums and token counts across all microbatches,
    # then computes the weighted mean in track_mtp_metrics. Older versions
    # accumulate one normalized loss per microbatch and still need averaging.
    tracker = MTPLossLoggingHelper.tracker
    uses_global_token_mean = "loss_sums" in tracker and tracker.get("calculate_per_token_loss", True)
    mtp_loss_scale = 1.0 if uses_global_token_mean else 1.0 / n_micro_batch

    # Create a dummy total_loss_dict to collect MTP metrics
    total_loss_dict = {}

    # Track MTP metrics - this will populate total_loss_dict with MTP losses
    MTPLossLoggingHelper.track_mtp_metrics(
        loss_scale=mtp_loss_scale, iteration=0, writer=None, wandb_writer=None, total_loss_dict=total_loss_dict
    )
    # Add MTP metrics to losses_reduced if any were collected
    # total_loss_dict: {'mtp_1 loss': tensor(value, device='cuda:0')}
    output = {}
    if total_loss_dict:
        for key, value in total_loss_dict.items():
            # Convert key to have proper prefix and format
            formatted_key = f"mtp_losses/{key.replace(' ', '_')}"
            # only added to the 0th batch, the MTP loss obtained is a global value, and will be the same for every batch
            output[formatted_key] = value.cpu().item()
    return output


def get_megatron_module_device(models: list[Any]) -> str:
    if not models:
        return "cpu"

    model_chunk = models[0]
    if not model_chunk.buffers or not isinstance(model_chunk.buffers, list):
        try:
            module = getattr(model_chunk, "module", model_chunk)
            return next(module.parameters()).device.type
        except StopIteration:
            return "cpu"

    buffer = model_chunk.buffers[0]
    if buffer.param_data is None:
        # use_distributed_optimizer=False: no flat param buffer, check module params directly
        try:
            return next(model_chunk.module.parameters()).device.type
        except StopIteration:
            return "cpu"
    if buffer.param_data.storage().size() == 0:
        return "cpu"
    else:
        return get_device_name()


def _get_mtp_num_layers(hf_config):
    """Get MTP layer count from various config formats.

    Supports:
        - num_nextn_predict_layers (DeepSeek, Qwen3 style)
        - mtp_num_hidden_layers (Qwen3.5 style, in hf_config or text_config)
    """
    if hasattr(hf_config, "num_nextn_predict_layers") and hf_config.num_nextn_predict_layers > 0:
        return hf_config.num_nextn_predict_layers
    if hasattr(hf_config, "mtp_num_hidden_layers") and hf_config.mtp_num_hidden_layers > 0:
        return hf_config.mtp_num_hidden_layers
    if hasattr(hf_config, "text_config") and hasattr(hf_config.text_config, "mtp_num_hidden_layers"):
        if hf_config.text_config.mtp_num_hidden_layers > 0:
            return hf_config.text_config.mtp_num_hidden_layers
    return 0


def _set_mtp_num_layers(hf_config, value: int):
    """Set MTP layer count in the appropriate config field."""
    if hasattr(hf_config, "num_nextn_predict_layers"):
        hf_config.num_nextn_predict_layers = value
    if hasattr(hf_config, "mtp_num_hidden_layers"):
        hf_config.mtp_num_hidden_layers = value
    if hasattr(hf_config, "text_config") and hasattr(hf_config.text_config, "mtp_num_hidden_layers"):
        hf_config.text_config.mtp_num_hidden_layers = value


def check_mtp_config(model_config: HFModelConfig, engine_config: McoreEngineConfig):
    """
    Check and configure MTP (Multi-Token Prediction) settings.

    Cases:
        - mtp.enable == False and no MTP layers: force provider MTP config to None
        - mtp.enable == False and has MTP layers: clear HF MTP fields and force provider MTP config to None
        - mtp.enable == True and no MTP layers: raise ValueError
        - mtp.enable == True and has MTP layers: configure override_transformer_config
    """
    hf_config = model_config.hf_config
    mtp_num_layers = _get_mtp_num_layers(hf_config)
    has_mtp = mtp_num_layers > 0
    enable_mtp = model_config.mtp.enable

    if not enable_mtp:
        _set_mtp_num_layers(hf_config, 0)

        # The non-vanilla Megatron-Bridge path reloads the HF config from local_path.
        # Force the provider override so MTP remains disabled after that reload.
        engine_config.override_transformer_config["mtp_num_layers"] = None
        engine_config.override_transformer_config.pop("mtp_loss_scaling_factor", None)
        return

    elif enable_mtp and not has_mtp:
        raise ValueError("enable mtp while model has no mtp layer, please use a model with mtp layer")
    elif enable_mtp and has_mtp:
        if "mtp_loss_scaling_factor" not in engine_config.override_transformer_config:
            engine_config.override_transformer_config["mtp_loss_scaling_factor"] = (
                model_config.mtp.mtp_loss_scaling_factor
            )
    return


def patch_engine_mtp(module, model_config):
    """
    Apply MTP patches to the model module.

    Args:
        module: The model module to patch. Can be a single module or a list of modules.
        model_config: The model configuration containing MTP settings.
    """
    logger.warning("Applying mtp patch...")
    from verl.models.mcore.mtp_patch import (
        patch_mtp_layer_checkpointed_forward,
        patch_mtp_layer_get_embeddings,
        patch_postprocess,
    )

    print(module)

    modules = module if isinstance(module, list) else [module]
    for m in modules:
        patch_postprocess(m)
        patch_mtp_layer_checkpointed_forward(m)
        if model_config.mtp.detach_encoder:
            patch_mtp_layer_get_embeddings(m)


@torch.no_grad()
def copy_megatron_model_to_cpu(models):
    """
    Copy Megatron model parameters to CPU memory (non-destructive copy).
    Unlike offload_megatron_model_to_cpu which moves data, this function creates
    independent copies on CPU while keeping GPU data intact.

    Args:
        models: List of model chunks (DDP-wrapped or unwrapped)

    Returns:
        dict: CPU state containing copied parameters and buffers
    """
    cpu_state = {}

    for model_idx, model_chunk in enumerate(models):
        if isinstance(model_chunk, DDP):
            # Handle DDP-wrapped models
            model_chunk_all_buffers = [model_chunk.buffers, model_chunk.expert_parallel_buffers]
            buffer_states = []

            for buffers in model_chunk_all_buffers:
                buffer_list = []
                for buffer in buffers:
                    buffer_state = {}

                    # Copy parameter data to CPU
                    if buffer.param_data.storage().size() > 0:
                        buffer_state["param_data"] = buffer.param_data.data.cpu().clone().pin_memory()
                    else:
                        buffer_state["param_data"] = buffer.param_data.cpu_data.clone().pin_memory()

                    buffer_list.append(buffer_state)
                buffer_states.append(buffer_list)

            cpu_state[f"model_chunk_{model_idx}"] = {"buffer_states": buffer_states, "is_ddp": True}
        else:
            # Handle non-DDP models (ref module)
            model_state = {}
            for name, param in model_chunk.named_parameters():
                param_state = {"data": param.data.cpu().clone().pin_memory()}
                model_state[name] = param_state

            cpu_state[f"model_chunk_{model_idx}"] = {"model_state": model_state, "is_ddp": False}

    return cpu_state


@torch.no_grad()
def restore_megatron_model_from_cpu(models, cpu_state):
    """
    Restore Megatron model parameters from CPU memory back to GPU.

    Args:
        models: List of model chunks to restore to
        cpu_state: CPU state dict returned from copy_megatron_model_to_cpu
    """
    for model_idx, model_chunk in enumerate(models):
        chunk_key = f"model_chunk_{model_idx}"
        if chunk_key not in cpu_state:
            continue

        chunk_state = cpu_state[chunk_key]

        if chunk_state["is_ddp"] and isinstance(model_chunk, DDP):
            # Restore DDP buffers
            model_chunk_all_buffers = [model_chunk.buffers, model_chunk.expert_parallel_buffers]
            buffer_states = chunk_state["buffer_states"]

            for buffers, buffer_list in zip(model_chunk_all_buffers, buffer_states, strict=False):
                for buffer, buffer_state in zip(buffers, buffer_list, strict=False):
                    # Restore parameter data
                    if "param_data" in buffer_state:
                        if buffer.param_data.storage().size() > 0:
                            buffer.param_data.data.copy_(buffer_state["param_data"].to(buffer.param_data.device))
                        else:
                            buffer.param_data.cpu_data.copy_(buffer_state["param_data"])

        elif not chunk_state["is_ddp"] and not isinstance(model_chunk, DDP):
            # Restore non-DDP models
            model_state = chunk_state["model_state"]
            for name, param in model_chunk.named_parameters():
                if name in model_state:
                    param_state = model_state[name]
                    param.data.copy_(param_state["data"].to(param.device))
