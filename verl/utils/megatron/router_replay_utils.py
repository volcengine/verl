# Copyright 2024 Bytedance Ltd. and/or its affiliates
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

"""
Router Replay Utilities
Utilities for handling router replay functionality in Megatron models.
"""

import inspect
import warnings

import torch

try:
    from megatron.core.pipeline_parallel.utils import is_vp_first_stage, is_vp_last_stage
except ImportError:
    warnings.warn("NPU not support router replay for now.", stacklevel=2)
    pass

from megatron.core import parallel_state as mpu
from megatron.core.pipeline_parallel.schedules import get_schedule_table
from megatron.core.tensor_parallel import gather_from_sequence_parallel_region, scatter_to_sequence_parallel_region
from megatron.core.transformer.transformer_config import TransformerConfig
from megatron.core.transformer.transformer_layer import get_transformer_layer_offset

from verl.models.mcore.util import (
    get_thd_quant_align_size,
    postprocess_packed_seqs,
    postprocess_thd_engine,
    preprocess_packed_seqs,
    preprocess_thd_engine,
)
from verl.utils.device import get_device_name
from verl.utils.megatron.router_replay_patch import RouterReplay, RouterReplayAction

device_name = get_device_name()


# from megatron.core.transformer.transformer_block import get_num_layers_to_build
def get_num_layers_to_build(config: TransformerConfig, vp_stage: int | None = None, pp_rank: int | None = None) -> int:
    """
    Determine the number of transformer layers to build for the current pipeline stage.
    Args:
        config (TransformerConfig): Configuration object containing transformer model parameters.
        vp_stage (Optional[int]): Virtual pipeline stage number.
        pp_rank (Optional[int]): Pipeline parallel rank.

    Returns:
        int: The number of layers to be built for the current pipeline stage.
    """
    # If we have a custom PP layout, straightforwardly
    # return the number of decoders in the layout array.
    if hasattr(config, "pipeline_model_parallel_layout") and config.pipeline_model_parallel_layout is not None:
        from megatron.core.transformer.enums import LayerType

        return config.pipeline_model_parallel_layout.get_num_layers_to_build(
            layer_type=LayerType.decoder, vp_stage=vp_stage
        )

    # Fallback for legacy tests.
    if pp_rank is None:
        pp_rank = mpu.get_pipeline_model_parallel_rank()

    is_first_pp_stage = pp_rank == 0
    is_last_pp_stage = pp_rank == config.pipeline_model_parallel_size - 1

    if config.num_layers_in_first_pipeline_stage is not None or config.num_layers_in_last_pipeline_stage is not None:
        assert not (config.account_for_embedding_in_pipeline_split or config.account_for_loss_in_pipeline_split), (
            " \
        Does not support standalone embedding stage and standalone loss stage with uneven pp"
        )
        # Number of layers to distribute over rest of pipeline stages
        layers_to_distribute = config.num_layers
        # Number of pipeline stages left for distributing transformer layers
        pipeline_stages_left = config.pipeline_model_parallel_size

        # If the uneven first (last) pipeline stage is enabled, remove the specified number
        # of layers to calculate the number of layers on each middle pipeline stage.
        if config.num_layers_in_first_pipeline_stage is not None:
            layers_to_distribute -= config.num_layers_in_first_pipeline_stage
            pipeline_stages_left -= 1

        if config.num_layers_in_last_pipeline_stage is not None:
            layers_to_distribute -= config.num_layers_in_last_pipeline_stage
            pipeline_stages_left -= 1

        # If pp_size <= 2, we do not have any intermediate pipeline stages, and we do not
        # need to check if the left over layers are divisible by the left over stages.
        if pipeline_stages_left > 0:
            assert layers_to_distribute % pipeline_stages_left == 0, (
                "With uneven pipelineing the left over layers must be divisible by left over stages"
            )
            num_layers_per_pipeline_rank = layers_to_distribute // pipeline_stages_left
        else:
            num_layers_per_pipeline_rank = 0

        # If the uneven first (last) pipeline stage is enabled, return the specified number
        # of layers for all virtual pipeline parallel stages within the first (last) pipeline
        # parallel stage.

        if is_first_pp_stage and config.num_layers_in_first_pipeline_stage is not None:
            num_layers_per_pipeline_rank = config.num_layers_in_first_pipeline_stage

        if is_last_pp_stage and config.num_layers_in_last_pipeline_stage is not None:
            num_layers_per_pipeline_rank = config.num_layers_in_last_pipeline_stage
    else:
        # Include the embedding layer and loss layer into pipeline parallelism partition
        num_layers = config.num_layers
        if config.account_for_embedding_in_pipeline_split:
            num_layers += 1

        if config.account_for_loss_in_pipeline_split:
            num_layers += 1

        assert num_layers % config.pipeline_model_parallel_size == 0, (
            "num_layers should be divisible by pipeline_model_parallel_size"
        )
        num_layers_per_pipeline_rank = num_layers // config.pipeline_model_parallel_size

    vp_size = config.virtual_pipeline_model_parallel_size
    if vp_size is not None and config.pipeline_model_parallel_size > 1:
        # Interleaved pipeline parallelism:
        # Number of layers in each model chunk is the number of layers in the stage,
        # divided by the number of model chunks in a stage.
        # With 8 layers, 2 stages, and 4 model chunks, we want an assignment of
        # layers to stages like (each list is a model chunk):
        # Stage 0: [0]  [2]  [4]  [6]
        # Stage 1: [1]  [3]  [5]  [7]
        # With 8 layers, 2 stages, and 2 virtual stages, we want an assignment of
        # layers to stages like (each list is a model chunk):
        # Stage 0: [0, 1]  [4, 5]
        # Stage 1: [2, 3]  [6, 7]

        assert num_layers_per_pipeline_rank % vp_size == 0, (
            f"num_layers_per_pipeline_rank {num_layers_per_pipeline_rank} \
            should be divisible by vp_size {vp_size}"
        )
        num_layers_per_virtual_stage = num_layers_per_pipeline_rank // vp_size

        num_layers_to_build = num_layers_per_virtual_stage

    else:
        # Non-interleaved pipeline parallelism:
        # Each stage gets a contiguous set of layers.
        num_layers_to_build = num_layers_per_pipeline_rank

    # The embedding (or loss) layer cannot function as a standalone transformer layer
    # Reduce the number of layers to construct by 1 on the first (or last) stage if the
    # embedding (or loss) layer is included in the pipeline parallelism partition and placement.
    if config.account_for_embedding_in_pipeline_split:
        if is_vp_first_stage(vp_stage, vp_size) and is_first_pp_stage:
            num_layers_to_build -= 1
            assert num_layers_to_build >= 0, "Not enough layers in the first virtual pipeline stage"

    if config.account_for_loss_in_pipeline_split:
        if is_vp_last_stage(vp_stage, vp_size) and is_last_pp_stage:
            num_layers_to_build -= 1
            assert num_layers_to_build >= 0, "Not enough layers in the last virtual pipeline stage"

    return num_layers_to_build


def is_moe_layer(tf_config, layer_idx):
    """Identify an MoE layer from the hybrid expert pattern or the configured MoE layer frequency."""
    hybrid_pattern = getattr(tf_config, "hybrid_pattern", None)
    if isinstance(hybrid_pattern, str):
        main_pattern = hybrid_pattern.split("/", 1)[0].replace("|", "")
        if len(main_pattern) == tf_config.num_layers and "E" in main_pattern:
            return main_pattern[layer_idx] == "E"

    moe_layer_freq = getattr(tf_config, "moe_layer_freq", None)

    if isinstance(moe_layer_freq, int):
        return layer_idx % moe_layer_freq == 0
    elif isinstance(moe_layer_freq, list):
        return moe_layer_freq[layer_idx] == 1
    else:
        raise ValueError(f"Unsupported moe_layer_freq type: {type(moe_layer_freq)}")


def get_moe_num_layers_to_build(
    config: TransformerConfig, vp_stage: int | None = None, pp_rank: int | None = None
) -> int:
    """Count the number of MoE layers assigned to the current rank.
    When ``moe_layer_freq`` is 1 or unset, every transformer layer is an MoE
    layer, so the count equals the total layer count. Otherwise only layers
    whose global index satisfies the frequency predicate are counted.
    Args:
        config: Megatron TransformerConfig providing layer layout information.
        vp_stage: Virtual-pipeline stage index (None defaults to current).
        pp_rank: Pipeline-parallel rank (None defaults to current).
    Returns:
        Number of MoE layers on the specified rank/stage.
    """
    total_layers = get_num_layers_to_build(config, vp_stage=vp_stage, pp_rank=pp_rank)

    sig = inspect.signature(get_transformer_layer_offset)
    # core 0.12.1 is not support vp_stage and pp_rank as parameters
    if "vp_stage" in sig.parameters and "pp_rank" in sig.parameters:
        layer_offset = get_transformer_layer_offset(config, vp_stage=vp_stage, pp_rank=pp_rank)
    elif "pp_rank" in sig.parameters:
        layer_offset = get_transformer_layer_offset(config, pp_rank=pp_rank)
    else:
        layer_offset = get_transformer_layer_offset(config)

    local_global_indices = range(layer_offset, layer_offset + total_layers)

    num_moe_layers = sum(1 for idx in local_global_indices if is_moe_layer(config, idx))

    return num_moe_layers


def _context_parallel_layout(tf_config) -> str:
    """Return the CP row layout used for THD packing, matching MegatronEngine.

    Router-replay tensors must be sharded exactly like the model's own token rows; otherwise the
    replayed routes are attached to the wrong tokens (or the shapes disagree outright, since the
    zigzag layout doubles the alignment). Keep this in sync with
    ``MegatronEngine._get_context_parallel_layout``.
    """
    if getattr(tf_config, "experimental_attention_variant", None) == "dsv4_hybrid":
        return "contiguous"
    return "zigzag"


def merge_router_topk_indices(
    attention_mask,
    input_ids,
    mini_layer_topk_idx_list,
    tf_config,
    vp_rank=None,
    local_cp_size=None,
    model=None,
    data_format: str = "thd",
):
    """
    Merge recorded router top-k indices across sequence-parallel ranks for all router instances,
    then pack/unpack them to align with the original (batch, seq_len) layout and append the result.

    Args:
        attention_mask (torch.Tensor): Attention mask of shape [batch_size, seq_len]. Used to determine
            the valid token positions during pack/unpack.
        input_ids (torch.Tensor): Input token IDs of shape [batch_size, seq_len]. Used together with
            attention_mask for sequence packing/unpacking.
        mini_layer_topk_idx_list (list): A Python list to which the merged top-k indices tensor will be appended.
        tf_config: Megatron/Transformer engine configuration object. Used to locate router instances for
            the current micro-batch.
        vp_rank (Optional[int]): Virtual pipeline stage rank override. If None, the current VP rank from
            Megatron parallel state will be used.
        model: The forwarded model chunk. When given, routes are collected from its own routers instead
            of inferring their location in the process-global router registry.
        data_format: Token layout used by the model. BSHD models record padded sequence-major rows;
            THD models record packed rows.

    Returns:
        None: The function has side effects only; it appends a tensor of shape
        [1, dynamic_bs_all, layer_num, topk] to mini_layer_topk_idx_list.
    """
    with torch.no_grad():
        if not input_ids.is_nested and attention_mask is None:
            raise RuntimeError("router replay RECORD requires attention_mask for non-nested BSHD inputs.")
        vp_rank = 0 if vp_rank is None else vp_rank
        if model is not None:
            model_routers = sorted(iter_model_routers(model), key=lambda item: item[0])
            layer_numbers = [layer_number for layer_number, _ in model_routers]
            if len(layer_numbers) != len(set(layer_numbers)):
                raise RuntimeError(
                    "router replay RECORD found duplicate layer numbers in the forwarded model: "
                    f"layer_numbers={layer_numbers}, vp_rank={vp_rank}"
                )
            router_instances_list = [router for _, router in model_routers]
        else:
            router_instances_list = RouterReplayHelper.get_micro_batch_router_list(tf_config, vp_rank)

        if not router_instances_list:
            expected = get_moe_num_layers_to_build(tf_config, vp_rank)
            if expected:
                raise RuntimeError(
                    "router replay RECORD found no routers in a stage that expects MoE layers: "
                    f"expected={expected}, vp_rank={vp_rank}"
                )
            topk = getattr(tf_config, "moe_router_topk", None)
            if not isinstance(topk, int) or topk <= 0:
                raise RuntimeError(
                    "router replay RECORD cannot build an empty local route map without a positive "
                    f"moe_router_topk, got {topk!r}."
                )
            if input_ids.is_nested:
                empty_routes = [
                    torch.empty((tokens.shape[0], 0, topk), dtype=torch.int16) for tokens in input_ids.unbind()
                ]
                mini_layer_topk_idx_list.append(torch.nested.as_nested_tensor(empty_routes, layout=torch.jagged))
            else:
                batch_size, seq_len = attention_mask.shape[:2]
                mini_layer_topk_idx_list.append(
                    torch.empty((batch_size, seq_len, 0, topk), dtype=torch.int16, device="cpu")
                )
            return

        recorded_local_positions = [
            idx for idx, router in enumerate(router_instances_list) if router.recorded_topk_idx is not None
        ]
        missing = [idx for idx, router in enumerate(router_instances_list) if router.recorded_topk_idx is None]
        if missing:
            local_rank_info = get_current_rank_layer_info(tf_config, vp_rank)
            raise RuntimeError(
                "router replay RECORD did not capture all local routers: "
                f"missing_local_positions={missing}, selected={len(router_instances_list)}, "
                f"registry={len(RouterReplay.router_instances)}, "
                f"recorded_local_positions={recorded_local_positions}, local_layer_range={local_rank_info}, "
                f"pp_rank={mpu.get_pipeline_model_parallel_rank()}, vp_rank={vp_rank}"
            )

        layers_topk_idx = []
        for router in router_instances_list:
            layers_topk_idx.append(router.recorded_topk_idx.to(torch.int16))  # dynamic_bs, topk

        # layer_num, dynamic_bs, topk  -> dynamic_bs, layer_num, topk
        layers_topk_idx = torch.stack(layers_topk_idx).permute(1, 0, 2).to(device_name)
        layers_topk_idx = layers_topk_idx.contiguous().view(torch.uint8)
        # dynamic_bs, layer_num, topk -> 1, dynamic_bs_all, layer_num, topk
        layers_topk_idx = (
            gather_from_sequence_parallel_region(layers_topk_idx, tensor_parallel_output_grad=False)
            .unsqueeze(0)
            .contiguous()
        )

        if data_format == "bshd":
            if not input_ids.is_nested:
                raise TypeError("BSHD router replay recording requires jagged input_ids")
            batch_size = input_ids.shape[0]
            if batch_size <= 0 or layers_topk_idx.shape[1] % batch_size:
                raise RuntimeError(
                    "BSHD router replay rows cannot be reshaped into a sequence-major batch: "
                    f"rows={layers_topk_idx.shape[1]}, batch={batch_size}"
                )
            padded_seqlen = layers_topk_idx.shape[1] // batch_size
            restored = layers_topk_idx.squeeze(0).contiguous().view(torch.int16)
            restored = restored.view(padded_seqlen, batch_size, *restored.shape[1:])
            lengths = [int(length) for length in input_ids.offsets().diff().tolist()]
            if any(length > padded_seqlen for length in lengths):
                raise RuntimeError(
                    f"BSHD router replay recorded only {padded_seqlen} rows per sample for lengths {lengths}"
                )
            parts = [restored[:length, sample].cpu() for sample, length in enumerate(lengths)]
            mini_layer_topk_idx_list.append(torch.nested.as_nested_tensor(parts, layout=torch.jagged))
            return
        if data_format != "thd":
            raise ValueError(f"Unsupported router replay data format: {data_format}")

        # RECORD and REPLAY must pack exactly like the model forward
        quant_align_size = get_thd_quant_align_size(tf_config)
        cp_layout = _context_parallel_layout(tf_config)
        min_local_rows = (
            tf_config.csa_window_size
            if getattr(tf_config, "experimental_attention_variant", None) == "dsv4_hybrid"
            else None
        )

        if input_ids.is_nested:
            batch_size = input_ids.shape[0]
            _, packed_seq_params, _ = preprocess_thd_engine(
                input_ids,
                pre_process=True,
                quant_align_size=quant_align_size,
                min_local_rows=min_local_rows,
                local_cp_size=local_cp_size,
                cp_layout=cp_layout,
            )
            layers_topk_idx = postprocess_thd_engine(
                layers_topk_idx,
                packed_seq_params,
                input_ids,
                batch_size,
                post_process=True,
                local_cp_size=local_cp_size,
                cp_layout=cp_layout,
            )
            # Undo the uint8 view. Nested tensors have no view(dtype), so reinterpret
            # the packed values buffer and re-wrap it on the same offsets.
            layers_topk_idx = torch.nested.nested_tensor_from_jagged(
                layers_topk_idx.values().contiguous().view(torch.int16), offsets=layers_topk_idx.offsets()
            )
        else:
            batch_size, seq_len = attention_mask.shape[:2]
            _, packed_seq_params = preprocess_packed_seqs(
                input_ids, attention_mask, pre_process=True, quant_align_size=quant_align_size
            )
            layers_topk_idx = postprocess_packed_seqs(
                layers_topk_idx, packed_seq_params, attention_mask, batch_size, seq_len, post_process=True
            )
            layers_topk_idx = layers_topk_idx.view(torch.int16)
        mini_layer_topk_idx_list.append(layers_topk_idx.cpu())


def _get_vision_token_type_rows(
    multi_modal_inputs,
    input_lens: list[int],
) -> list[list[int]] | None:
    """Return valid DeepSeek-V4.1 vision-type rows, if present.

    V4.1 training inputs contain the expanded image span, while vLLM's routed
    expert response can still be indexed by the compact placeholder sequence.
    Keeping this extraction in the replay utility makes the alignment code
    independent of the particular batch container used by the engine.
    """
    if not multi_modal_inputs or "vision_token_types" not in multi_modal_inputs:
        return None

    vision_token_types = multi_modal_inputs["vision_token_types"]
    if not isinstance(vision_token_types, torch.Tensor):
        raise TypeError("vision_token_types must be a tensor for R3 router replay")
    if vision_token_types.ndim != 2 or vision_token_types.shape[0] != len(input_lens):
        raise ValueError(
            "vision_token_types must have shape [batch, sequence] matching input_ids; "
            f"got {tuple(vision_token_types.shape)} for {len(input_lens)} sequences"
        )
    if any(length > vision_token_types.shape[1] for length in input_lens):
        raise ValueError(
            "vision_token_types is shorter than the expanded input sequence: "
            f"types={vision_token_types.shape[1]}, input_lengths={input_lens}"
        )

    return [
        vision_token_types[sample, :length].detach().to(device="cpu", dtype=torch.int64).tolist()
        for sample, length in enumerate(input_lens)
    ]


def _align_r3_multimodal_routes(routes: torch.Tensor, vision_types: list[int]) -> torch.Tensor:
    """Expand compact V4.1 routes into the actor's image-expanded sequence.

    vLLM currently returns one route row for an image placeholder even though
    the Megatron V4.1 actor executes one row for every image-span position.
    The placeholder route cannot be reused for all visual positions because
    V4.1 uses modality-specific router biases.  Consume that compact row and
    leave the expanded visual rows as ignored placeholders; the replay mask
    selects native Megatron routing for those rows.
    """
    expanded_len = len(vision_types)
    route_len = routes.shape[0]
    image_start_count = sum(kind == 0 for kind in vision_types)
    image_position_count = sum(kind >= 0 for kind in vision_types)
    text_count = sum(kind == -1 for kind in vision_types)
    compact_len = text_count + image_start_count
    zero = torch.zeros((1, *routes.shape[1:]), dtype=routes.dtype, device=routes.device)

    # A complete expanded response (or its autoregressive final-row omission)
    # is already position aligned. Keep the actual visual routes in this case;
    # callers may still choose native visual routing through the replay mask.
    if route_len in (expanded_len, expanded_len - 1):
        rows = [routes[index : index + 1] if index < route_len else zero for index in range(expanded_len)]
        return torch.cat(rows, dim=0)

    # vLLM may emit a different number of rows for an image span than the
    # actor's expanded sequence.  Text rows stay position-aligned; image rows
    # are consumed inside the visual span and are ignored by the replay mask.
    # This covers compact placeholders, partial visual expansion, and a missing
    # final autoregressive row without reusing a visual route for text.
    if text_count - 1 <= route_len <= expanded_len:
        if route_len == compact_len:
            text_route_count = text_count
            image_route_count = image_start_count
        elif route_len == compact_len - 1:
            text_route_count = text_count - 1
            image_route_count = image_start_count
        else:
            text_route_count = text_count if route_len >= text_count else text_count - 1
            image_route_count = route_len - text_route_count
        if image_route_count < 0 or image_route_count > image_position_count:
            raise RuntimeError(
                "R3 router replay cannot partition DeepSeek-V4.1 multimodal routes: "
                f"{route_len} route rows for {expanded_len} expanded tokens, "
                f"{text_count} text rows and {image_position_count} image rows"
            )
        rows = []
        cursor = 0
        text_cursor = 0
        image_cursor = 0
        for kind in vision_types:
            if kind == -1:
                if text_cursor < text_route_count:
                    rows.append(routes[cursor : cursor + 1])
                    cursor += 1
                    text_cursor += 1
                else:
                    rows.append(zero)
            elif image_cursor < image_route_count:
                # Native V4.1 routing owns visual rows; these values are
                # retained only to preserve the returned row count.
                if cursor < route_len:
                    rows.append(routes[cursor : cursor + 1] if route_len > compact_len else zero)
                    cursor += 1
                    image_cursor += 1
                else:
                    rows.append(zero)
            else:
                rows.append(zero)
        if cursor != route_len or image_cursor != image_route_count:
            raise RuntimeError(
                "V4.1 multimodal router replay did not consume all route rows: "
                f"consumed={cursor}, routes={route_len}, expanded={expanded_len}, "
                f"compact={compact_len}, text_routes={text_cursor}, image_routes={image_cursor}"
            )
        return torch.cat(rows, dim=0)

    raise RuntimeError(
        "R3 router replay cannot align DeepSeek-V4.1 multimodal routes: "
        f"{route_len} route rows for {expanded_len} expanded tokens, "
        f"{compact_len} compact tokens ({image_start_count} image spans)"
    )


def build_r3_replay_mask(
    input_ids: torch.Tensor,
    response_mask: torch.Tensor,
    multi_modal_inputs=None,
) -> torch.Tensor:
    """Build a full-sequence replay mask for rollout-captured routes.

    Response logprobs are read from shifted model rows, but those rows attend to
    earlier hidden states whose MoE routing also affects the result. Replay every
    causal row that can influence response logprobs and skip only the final
    response row, whose logits are not used by ``no_padding_2_padding``.
    """
    total_lens = input_ids.offsets().diff()
    input_lens = [int(length) for length in total_lens.tolist()]
    vision_rows = _get_vision_token_type_rows(multi_modal_inputs, input_lens)
    if vision_rows is not None:
        response_lens = response_mask.sum(dim=-1).to(device=total_lens.device, dtype=total_lens.dtype)
        mask_parts = []
        for sample, (total_len, response_len) in enumerate(zip(input_lens, response_lens.tolist(), strict=True)):
            replay_len = total_len - 1 if response_len > 0 else 0
            part = torch.zeros(total_len, dtype=torch.bool, device=total_lens.device)
            if replay_len:
                part[:replay_len] = True
            image_mask = torch.tensor(
                [kind >= 0 for kind in vision_rows[sample]],
                dtype=torch.bool,
                device=part.device,
            )
            part &= ~image_mask
            mask_parts.append(part)
        return torch.nested.as_nested_tensor(mask_parts, layout=torch.jagged)

    response_lens = response_mask.sum(dim=-1).to(device=total_lens.device, dtype=total_lens.dtype)
    bs = total_lens.size(0)
    values = torch.tensor([True, False], dtype=torch.bool, device=total_lens.device).repeat(bs)
    replay_lens = torch.where(response_lens > 0, total_lens - 1, torch.zeros_like(total_lens))
    suffix_lens = total_lens - replay_lens
    counts = torch.stack([replay_lens, suffix_lens], dim=1).flatten()
    mask_values = torch.repeat_interleave(values, counts)
    return torch.nested.nested_tensor_from_jagged(mask_values, offsets=input_ids.offsets())


def align_r3_router_replay_data(
    layers_topk_idx: torch.Tensor,
    input_ids: torch.Tensor,
    multi_modal_inputs=None,
) -> torch.Tensor:
    """Align rollout routes with full training inputs one sequence at a time.

    Autoregressive rollout records the routes used to predict each generated
    token, so it has no route for the final generated token. The R3 replay mask
    leaves that final model row native; append one ignored placeholder per
    affected sequence so route and model tensors still have identical shapes.
    """
    if not layers_topk_idx.is_nested or not input_ids.is_nested:
        raise TypeError("R3 router replay requires jagged route targets and input_ids")

    route_parts = list(layers_topk_idx.unbind())
    input_lens = [int(length) for length in input_ids.offsets().diff().tolist()]
    if len(route_parts) != len(input_lens):
        raise RuntimeError(
            f"R3 router replay has {len(route_parts)} route sequences for {len(input_lens)} input sequences"
        )

    vision_rows = _get_vision_token_type_rows(multi_modal_inputs, input_lens)
    aligned_parts = []
    for sample_id, (routes, input_len) in enumerate(zip(route_parts, input_lens, strict=True)):
        if vision_rows is not None:
            aligned_parts.append(_align_r3_multimodal_routes(routes, vision_rows[sample_id]))
            continue
        route_len = routes.shape[0]
        if route_len == input_len:
            aligned_parts.append(routes)
        elif route_len == input_len - 1:
            placeholder = torch.zeros((1, *routes.shape[1:]), dtype=routes.dtype, device=routes.device)
            aligned_parts.append(torch.cat((routes, placeholder), dim=0))
        else:
            raise RuntimeError(
                f"R3 router replay sample {sample_id} has {route_len} route rows for {input_len} input tokens; "
                "expected equal lengths or exactly one missing final route"
            )

    return torch.nested.as_nested_tensor(aligned_parts, layout=torch.jagged)


def set_router_replay_data(
    layers_topk_idx,
    attention_mask,
    tf_config,
    vp_rank=None,
    replay_mask=None,
    local_cp_size=None,
    model=None,
    data_format: str = "thd",
    forced_max_seqlen: int | None = None,
):
    """
    Scatter the packed router top-k indices back to sequence-parallel ranks and update each local
    RouterReplay instance with target indices for replay mode.

    This function prepares the per-layer, per-sample top-k routing decisions (recorded during an earlier
    forward) so that subsequent replay passes can follow exactly the same routing.

    Args:
        layers_topk_idx (torch.Tensor): Router top-k indices with shape [bs, max_seq_len, layer_num, topk].
            This should be the merged output produced by merge_router_topk_indices.
        attention_mask (torch.Tensor): Attention mask [batch_size, seq_len] used for pack/unpack alignment.
        tf_config: Megatron/Transformer engine configuration object.
        vp_rank (Optional[int]): Virtual pipeline stage rank override. If None, the current VP rank from
            Megatron parallel state will be used.
        replay_mask (Optional[torch.Tensor]): Optional per-token mask. Masked tokens use replayed routes;
            unmasked tokens keep native Megatron routes.
        model: The forwarded model (or list of VPP chunks). When given, targets are written to its own
            routers instead of a positional slice of the global RouterReplay.router_instances list.
        data_format: Token layout used by the model. BSHD replay restores sequence-major padded rows;
            THD replay uses the existing packed-sequence helpers.
        forced_max_seqlen: Optional BSHD padding length chosen by the engine for this micro-batch.

    Returns:
        None: The function updates internal RouterReplay instances in-place.
    """
    if layers_topk_idx is None:
        raise RuntimeError("router_replay REPLAY requires routed_experts from the preceding RECORD forward.")

    with torch.no_grad():
        vp_rank = 0 if vp_rank is None else vp_rank
        # RECORD and REPLAY must pack exactly like the model forward
        quant_align_size = get_thd_quant_align_size(tf_config)
        cp_layout = _context_parallel_layout(tf_config)
        min_local_rows = (
            tf_config.csa_window_size
            if getattr(tf_config, "experimental_attention_variant", None) == "dsv4_hybrid"
            else None
        )

        replay_mask_rmpad = None
        if data_format == "bshd":
            if layers_topk_idx.is_nested:
                route_parts = list(layers_topk_idx.unbind())
                lengths = [int(length) for length in layers_topk_idx.offsets().diff().tolist()]
                if not route_parts:
                    raise RuntimeError("BSHD router replay requires at least one sequence")
                max_seqlen = int(forced_max_seqlen) if forced_max_seqlen is not None else max(lengths)
                if max_seqlen < max(lengths):
                    raise ValueError(f"forced_max_seqlen={max_seqlen} is smaller than router replay lengths {lengths}")
                trailing_shape = tuple(route_parts[0].shape[1:])
                padded = torch.zeros(
                    (len(route_parts), max_seqlen, *trailing_shape),
                    dtype=layers_topk_idx.dtype,
                    device=layers_topk_idx.device,
                )
                for sample, (part, length) in enumerate(zip(route_parts, lengths, strict=True)):
                    padded[sample, :length].copy_(part)
                layers_topk_idx_rmpad = padded.transpose(0, 1).reshape(1, -1, *trailing_shape)

                if replay_mask is not None:
                    mask_parts = list(replay_mask.unbind())
                    if [part.shape[0] for part in mask_parts] != lengths:
                        raise RuntimeError("BSHD router replay mask lengths do not match route lengths")
                    padded_mask = torch.zeros(
                        (len(mask_parts), max_seqlen),
                        dtype=torch.bool,
                        device=replay_mask.device,
                    )
                    for sample, (part, length) in enumerate(zip(mask_parts, lengths, strict=True)):
                        padded_mask[sample, :length].copy_(part.bool())
                    replay_mask_rmpad = padded_mask.transpose(0, 1).reshape(1, -1)
            else:
                if attention_mask is None:
                    raise RuntimeError("router replay REPLAY requires attention_mask for dense BSHD inputs.")
                layers_topk_idx_rmpad = layers_topk_idx.transpose(0, 1).reshape(1, -1, *layers_topk_idx.shape[2:])
                if replay_mask is not None:
                    replay_mask_rmpad = replay_mask.transpose(0, 1).reshape(1, -1)
        elif data_format != "thd":
            raise ValueError(f"Unsupported router replay data format: {data_format}")
        elif layers_topk_idx.is_nested:
            layers_topk_idx_rmpad, _, _ = preprocess_thd_engine(
                layers_topk_idx,
                pre_process=True,
                quant_align_size=quant_align_size,
                min_local_rows=min_local_rows,
                local_cp_size=local_cp_size,
                cp_layout=cp_layout,
            )
            if replay_mask is not None:
                replay_mask_rmpad, _, _ = preprocess_thd_engine(
                    replay_mask,
                    pre_process=True,
                    quant_align_size=quant_align_size,
                    min_local_rows=min_local_rows,
                    local_cp_size=local_cp_size,
                    cp_layout=cp_layout,
                )
        else:
            if attention_mask is None:
                raise RuntimeError("router replay REPLAY requires attention_mask for non-nested BSHD inputs.")
            layers_topk_idx_rmpad, _ = preprocess_packed_seqs(
                layers_topk_idx, attention_mask, pre_process=True, quant_align_size=quant_align_size
            )
        layers_topk_idx_rmpad = layers_topk_idx_rmpad.contiguous()  # 1, dynamic_bs_all, layer_num, topk

        # 1, dynamic_bs_split, layer_num, topk
        layers_topk_idx_rmpad_split = scatter_to_sequence_parallel_region(
            layers_topk_idx_rmpad.to(device_name).squeeze(dim=0)
        ).unsqueeze(dim=0)
        replay_mask_rmpad_split = None
        if replay_mask_rmpad is not None:
            replay_mask_rmpad_split = scatter_to_sequence_parallel_region(
                replay_mask_rmpad.to(device_name).squeeze(dim=0)
            )

        # dynamic_bs_split, layer_num, topk -> layer_num, dynamic_bs_split, topk
        layers_topk_idx_reshape = layers_topk_idx_rmpad_split.permute(0, 2, 1, 3).squeeze(
            dim=0
        )  # layer_num, dynamic_bs_all, topk
        # vLLM retains dense HF blocks; hybrid Megatron models can expand each
        # block into multiple modules. R2 instead records only MoE modules.
        route_count = layers_topk_idx_reshape.shape[0]
        moe_module_count = sum(1 for i in range(tf_config.num_layers) if is_moe_layer(tf_config, i))
        if route_count == tf_config.num_layers:
            route_index = "module"
        elif route_count == moe_module_count:
            route_index = "moe"
        elif moe_module_count < route_count < tf_config.num_layers and tf_config.num_layers % route_count == 0:
            route_index = "block"
        else:
            raise ValueError(
                f"Cannot map {route_count} route layers to {tf_config.num_layers} modules "
                f"with {moe_module_count} MoE layers"
            )

        def _route_idx(layer_idx: int) -> int:
            """Map a Megatron module index to the captured route-tensor row."""
            if route_index == "module":
                return layer_idx
            if route_index == "block":
                return layer_idx // (tf_config.num_layers // route_count)
            return sum(1 for i in range(layer_idx) if is_moe_layer(tf_config, i))

        if model is not None:
            model_routers = list(iter_model_routers(model))
            if not model_routers:
                raise RuntimeError("router_replay REPLAY found no routers in the forwarded model.")

            missing_layer_numbers = []
            for layer_number, router in model_routers:
                layer_idx = layer_number - 1
                if not is_moe_layer(tf_config, layer_idx):
                    continue
                idx = _route_idx(layer_idx)
                if not 0 <= idx < layers_topk_idx_reshape.shape[0]:
                    missing_layer_numbers.append(layer_number)
                    continue
                router.set_target_indices(
                    layers_topk_idx_reshape[idx].to(torch.int64),
                    replay_mask=replay_mask_rmpad_split,
                )
            if missing_layer_numbers:
                raise RuntimeError(
                    "router_replay REPLAY data does not cover every forwarded MoE layer: "
                    f"missing_layer_numbers={missing_layer_numbers}, route_layers={layers_topk_idx_reshape.shape[0]}, "
                    f"vp_rank={vp_rank}"
                )
            return

        local_rank_info = get_current_rank_layer_info(tf_config, vp_rank)
        offset, end = local_rank_info["start"], local_rank_info["end"]
        router_instances_list = RouterReplayHelper.get_micro_batch_router_list(tf_config, vp_rank)

        router_offset = 0
        for layer_idx in range(offset, end):
            if not is_moe_layer(tf_config, layer_idx):
                continue
            router = router_instances_list[router_offset]
            idx = _route_idx(layer_idx)
            router.set_target_indices(
                layers_topk_idx_reshape[idx].to(torch.int64),
                replay_mask=replay_mask_rmpad_split,
            )
            router_offset += 1


def iter_model_routers(model):
    """Yield ``(layer_number, RouterReplay)`` for every replay-enabled router owned by ``model``.

    ``model`` is a single module or the list of virtual-pipeline chunks. The process-global
    ``RouterReplay.router_instances`` list can hold more routers than this model has local layers —
    a model that rebuilds its decoder registers a set it then discards — so a positional slice of it
    can address the wrong objects. Walking the forwarded model reaches each layer's own router.
    """
    for chunk in model if isinstance(model, list | tuple) else [model]:
        chunk = getattr(chunk, "language_model", chunk)
        # Scope to the decoder: MTP layers restart layer numbering at 1, so they alias decoder
        # layers, and the replay tensor carries no MTP rows. ``mtp`` is a sibling of ``decoder``
        # on both GPTModel and HybridModel, the only two classes that build one.
        for module in getattr(chunk, "decoder", chunk).modules():
            router = getattr(module, "router_replay", None)
            if router is not None and getattr(module, "layer_number", None) is not None:
                yield module.layer_number, router


def set_model_router_replay_action(model, router_replay_action):
    """Set the router replay action on the forwarded model's own routers.

    Mirrors the module walk in ``set_router_replay_data``. Toggling through the positional slice can
    miss the real routers, leaving them stuck in REPLAY_FORWARD so the backward recompute reads a
    stale cross-micro-batch ``target_topk_idx`` instead of popping its own entry from
    ``replay_backward_list``.
    """
    for _, router in iter_model_routers(model):
        router.set_router_replay_action(router_replay_action)


def reorder_and_merge_vpp_layers(
    micro_batch_tensor_list,
    num_microbatches: int,
    vpp_size: int,
    microbatch_group_size_per_vp_stage: int,
) -> torch.Tensor:
    """
    Reorder and merge per-VPP layer blocks into a contiguous layer dimension.

    Given a tensor shaped as [bs*vpp_size, max_token_len, layer_num_per_vpp, topk], this function:
    1) Builds the schedule table for virtual microbatches and reorders the first dimension so that entries
       belonging to the same model chunk (VPP stage) become contiguous.
    2) Reshapes and merges the (vpp_size, layer_num_per_vpp) into a single layer dimension, producing
       [bs, max_token_len, layer_num, topk].

    Args:
        micro_batch_tensor_list : the list of Input tensor.
        num_microbatches (int): Number of microbatches per pipeline stage (bs).
        vpp_size (int): Virtual pipeline parallel size (number of model chunks).
        microbatch_group_size_per_vp_stage (int): Number of consecutive microbatches processed per VPP stage.

    Returns:
        torch.Tensor: Output tensor of shape [bs, max_token_len, layer_num, topk].

    Raises:
        ValueError: If input tensor dimensionality or expected sizes do not match.
        RuntimeError: If the computed output shape is unexpected or the schedule length mismatches.
    """
    # 1) Build schedule table: map each virtual_microbatch_id -> (microbatch_id, model_chunk_id)
    schedule_table = get_schedule_table(num_microbatches, vpp_size, microbatch_group_size_per_vp_stage)
    if len(micro_batch_tensor_list) != len(schedule_table):
        raise RuntimeError(
            "R2 RECORD must capture every scheduled microbatch/chunk, including zero-layer chunks: "
            f"captured={len(micro_batch_tensor_list)}, expected={len(schedule_table)}"
        )

    # 2) Group by model_chunk_id to build reorder indices so entries of the same chunk become contiguous along dim 0
    tensor_by_chunk = [[] for _ in range(vpp_size)]
    mini_tensor_list = []

    for vidx, (_mb, chunk_id) in enumerate(schedule_table):
        tensor_by_chunk[chunk_id].append(micro_batch_tensor_list[vidx])

    if micro_batch_tensor_list[0].is_nested:
        for chunk_id in range(vpp_size):
            mini_tensor_list.append(merge_nested_router_maps(tensor_by_chunk[chunk_id]))
    else:
        for chunk_id in range(vpp_size):
            mini_tensor_list.append(torch.cat(tensor_by_chunk[chunk_id], dim=0))

    out = torch.cat(mini_tensor_list, dim=2)

    return out


def merge_nested_router_maps(router_maps) -> torch.Tensor:
    """Flatten recorded micro-batch routes into one int16 jagged tensor."""
    tensors = [tensor.to(torch.int16) for router_map in router_maps for tensor in router_map.unbind()]
    return torch.nested.as_nested_tensor(tensors, layout=torch.jagged)


def get_current_rank_layer_info(tf_config, vp_rank=None):
    # When vp_rank is None, default to the current VP rank (or 0 if VP is disabled).
    """Return the local layer range/count for the current process and the full assignment table.

    Args:
        tf_config: Configuration object used by compute_pipeline_layer_assignment.
        vp_rank (Optional[int]): Explicit virtual pipeline stage rank to query. If None, uses
            mpu.get_virtual_pipeline_model_parallel_rank() when VP is enabled; otherwise 0.

    Returns:
        Tuple[dict, dict]: A tuple of (local_assignment, all_assignments) where local_assignment contains
        keys {"start", "end", "count"} for the current (pp_rank, vp_stage).
    """
    if vp_rank is None:
        vp_rank = 0
    num_layers_to_build = get_num_layers_to_build(tf_config, vp_stage=vp_rank)

    sig = inspect.signature(get_transformer_layer_offset)

    if "vp_stage" in sig.parameters:
        offset = get_transformer_layer_offset(tf_config, vp_stage=vp_rank)
    else:
        offset = get_transformer_layer_offset(tf_config)
    local = {}
    local["start"] = offset
    local["end"] = offset + num_layers_to_build
    local["count"] = num_layers_to_build
    return local


def pp_gather(local_layers_router_map, tf_config):
    """
    Gather local router maps from all PP ranks into a global router map.

    Args:
        local_layers_router_map (torch.Tensor): Local router map of shape
            [bs, max_seq_len, local_num_layers, topk].
        tf_config: Configuration providing pipeline_model_parallel_size.

    Returns:
        torch.Tensor: Global router map of shape [bs, max_seq_len, num_layers, topk] placed on CPU.
    """
    pp_size = tf_config.pipeline_model_parallel_size
    if pp_size <= 1:
        return local_layers_router_map

    pp_group = mpu.get_pipeline_model_parallel_group()
    world_size = torch.distributed.get_world_size(pp_group)
    if world_size != pp_size:
        raise RuntimeError(f"pipeline group size {world_size} does not match configured PP size {pp_size}.")
    if local_layers_router_map.is_nested:
        # all_gather_object preserves each sender's CUDA device, so normalize
        # jagged route maps before concatenating routes from local PP ranks.
        local_layers_router_map = local_layers_router_map.to("cpu")
        layers_topk_idx_global_list = [None] * world_size
        torch.distributed.all_gather_object(layers_topk_idx_global_list, local_layers_router_map, pp_group)
    else:
        # PP stages may own different numbers of MoE layers, including zero. Exchange
        # layer counts, pad only that dimension for NCCL, then remove the padding.
        # NCCL has no int16 datatype, so payloads travel as bit-identical uint8 views.
        payload = local_layers_router_map.to(device_name).contiguous().view(torch.uint8)
        local_layer_count = torch.tensor([local_layers_router_map.shape[2]], dtype=torch.int64, device=payload.device)
        gathered_layer_counts = [torch.empty_like(local_layer_count) for _ in range(world_size)]
        torch.distributed.all_gather(
            tensor=local_layer_count,
            tensor_list=gathered_layer_counts,
            group=pp_group,
            async_op=False,
        )
        layer_counts = [int(count.item()) for count in gathered_layer_counts]
        max_layer_count = max(layer_counts)
        if max_layer_count == 0:
            layers_topk_idx_global_list = [local_layers_router_map for _ in range(world_size)]
        else:
            if payload.shape[2] != max_layer_count:
                padded_shape = list(payload.shape)
                padded_shape[2] = max_layer_count
                padded_payload = torch.zeros(padded_shape, dtype=payload.dtype, device=payload.device)
                padded_payload[:, :, : payload.shape[2], :].copy_(payload)
                payload = padded_payload
            gathered_payloads = [torch.empty_like(payload) for _ in range(world_size)]
            torch.distributed.all_gather(
                tensor=payload,
                tensor_list=gathered_payloads,
                group=pp_group,
                async_op=False,
            )
            layers_topk_idx_global_list = [
                tensor[:, :, :layer_count, :].contiguous().view(torch.int16)
                for tensor, layer_count in zip(gathered_payloads, layer_counts, strict=True)
            ]
    vp_size = tf_config.virtual_pipeline_model_parallel_size
    if vp_size is not None:
        vpp_router_map_offset = [[] for _ in range(pp_size)]
        for pp_stage in range(pp_size):
            vpp_router_map_offset[pp_stage].append(0)
            for vp_stage in range(vp_size):
                num_layers_to_build = get_moe_num_layers_to_build(tf_config, vp_stage, pp_stage)
                vpp_router_map_offset[pp_stage].append(num_layers_to_build + vpp_router_map_offset[pp_stage][-1])
        layers_topk_idx_global = []
        for vp_stage in range(vp_size):
            for pp_stage in range(pp_size):
                piece = slice(vpp_router_map_offset[pp_stage][vp_stage], vpp_router_map_offset[pp_stage][vp_stage + 1])
                if layers_topk_idx_global_list[pp_stage].is_nested:
                    nested_item = layers_topk_idx_global_list[pp_stage]
                    sliced_tensors = [t[:, piece, :] for t in nested_item.unbind()]
                    sliced_nested = torch.nested.as_nested_tensor(sliced_tensors, layout=torch.jagged)
                    layers_topk_idx_global.append(sliced_nested)
                else:
                    layers_topk_idx_global.append(layers_topk_idx_global_list[pp_stage][:, :, piece, :])
        global_router_map = torch.cat(layers_topk_idx_global, dim=2).to("cpu")
    else:
        global_router_map = torch.cat(layers_topk_idx_global_list, dim=2).to("cpu")

    return global_router_map


class RouterReplayHelper:
    """Helper class to query router replay state and locate local RouterReplay instances."""

    @staticmethod
    def get_micro_batch_router_list(tf_config, vp_rank=None):
        """
        Return the list of RouterReplay instances corresponding to the current micro-batch and local
        (pp_rank, vp_stage) layer range.

        Accept either one PP rank's complete registry in local VPP order, or one complete
        model's registry in global layer order. These positional layouts must not contain
        stale routers or routers from other models; use the model-scoped helpers for those cases.

        Args:
            tf_config: Configuration object used to compute layer assignments.
            vp_rank (Optional[int]): Explicit virtual pipeline stage to query. If None, the current VP
                rank from Megatron parallel state is used when available.
        Returns:
            list: A contiguous sublist of RouterReplay.router_instances for the local layer range.
        """
        if not RouterReplay.router_instances:
            return []

        vp_size = tf_config.virtual_pipeline_model_parallel_size or 1
        vp_rank = 0 if vp_rank is None else vp_rank
        if not 0 <= vp_rank < vp_size:
            raise ValueError(f"vp_rank={vp_rank} is outside the configured VPP size {vp_size}.")

        local_counts = [get_moe_num_layers_to_build(tf_config, stage) for stage in range(vp_size)]
        local_total = sum(local_counts)
        global_total = sum(is_moe_layer(tf_config, idx) for idx in range(tf_config.num_layers))
        registry_size = len(RouterReplay.router_instances)
        if registry_size == local_total:
            offset = sum(local_counts[:vp_rank])
        elif registry_size == global_total:
            layer_start = get_current_rank_layer_info(tf_config, vp_rank)["start"]
            offset = sum(is_moe_layer(tf_config, idx) for idx in range(layer_start))
        else:
            raise RuntimeError(
                "router replay registry does not cover a complete local PP/VPP or global model layout: "
                f"registry={registry_size}, local_expected={local_total}, global_expected={global_total}, "
                f"vp_rank={vp_rank}. Use model-scoped replay for non-positional registries."
            )
        return RouterReplay.router_instances[offset : offset + local_counts[vp_rank]]

    @staticmethod
    def _get_action_router_list(tf_config, vp_rank=None, model=None):
        if model is not None:
            return [router for _, router in iter_model_routers(model)]
        return RouterReplayHelper.get_micro_batch_router_list(tf_config, vp_rank)

    @staticmethod
    def is_r2_record_action(tf_config, vp_rank=None, model=None) -> bool:
        """Return True if the current router_replay_action is RECORD (R2) for the local router instances.

        This inspects the first local RouterReplay instance's router_replay_action and compares it to
        RouterReplayAction.RECORD.
        """
        router_instances_list = RouterReplayHelper._get_action_router_list(tf_config, vp_rank, model)
        return bool(router_instances_list) and (
            router_instances_list[0].router_replay_action == RouterReplayAction.RECORD
        )

    @staticmethod
    def is_replay_forward_action(tf_config, vp_rank=None, model=None) -> bool:
        """Return True if the current router_replay_action is REPLAY_FORWARD for the local router instances.

        This inspects the first local RouterReplay instance's router_replay_action and compares it to
        RouterReplayAction.REPLAY_FORWARD.
        """
        router_instances_list = RouterReplayHelper._get_action_router_list(tf_config, vp_rank, model)
        return (
            bool(router_instances_list)
            and router_instances_list[0].router_replay_action == RouterReplayAction.REPLAY_FORWARD
        )

    @staticmethod
    def is_replay_backward_action(tf_config, vp_rank=None, model=None) -> bool:
        """Return True if the current router_replay_action is REPLAY_BACKWARD for the local router instances.

        This inspects the first local RouterReplay instance's router_replay_action and compares it to
        RouterReplayAction.REPLAY_BACKWARD.
        """
        router_instances_list = RouterReplayHelper._get_action_router_list(tf_config, vp_rank, model)
        return (
            bool(router_instances_list)
            and router_instances_list[0].router_replay_action == RouterReplayAction.REPLAY_BACKWARD
        )
