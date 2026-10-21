# Copyright 2025 Bytedance Ltd. and/or its affiliates
# Copyright (c) 2025, NVIDIA CORPORATION. All rights reserved.
# Copyright Amazon.com, Inc. or its affiliates. All Rights Reserved.
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
from typing import Optional

import torch
from torch.nested._internal.nested_tensor import NestedTensor

from verl.utils.megatron_utils import unwrap_model

from .util import (
    build_vlm_attn_mask_bshd,
    get_fp8_padding_options,
    postprocess_bshd_engine,
    postprocess_thd_engine,
    preprocess_bshd_engine,
    preprocess_thd_engine,
    preprocess_vlm_thd_engine,
)


def _convert_to_nested_tensor(v, input_ids_lengths):
    """Convert regular tensor to NestedTensor, slicing according to input_ids_lengths.

    Args:
        v: Tensor to convert, shape [batch, seq_len]
        input_ids_lengths: List of valid lengths for each sample

    Returns:
        Converted NestedTensor
    """
    if isinstance(v, NestedTensor):
        return v

    batch_size = v.shape[0]
    assert len(input_ids_lengths) == batch_size, (
        f"len(input_ids_lengths)={len(input_ids_lengths)} != batch_size={batch_size}"
    )

    v_split_list = []
    for i in range(batch_size):
        vi = v[i]
        target_len = input_ids_lengths[i]
        if vi.shape[0] > target_len:
            vi = vi[:target_len]
        elif vi.shape[0] < target_len:
            vi = torch.cat([vi, torch.ones(target_len - vi.shape[0], dtype=vi.dtype, device=vi.device)])
        v_split_list.append(vi)

    v = torch.nested.nested_tensor(v_split_list, layout=torch.jagged)
    return v


def _build_mtp_loss_mask_nested(response_mask, input_ids_lengths, response_attention_mask):
    """Build a nested loss_mask aligned to ``input_ids = [prompt; response]`` for MTP.

    ``response_mask`` is response-only data. This expands it to full packed
    input length as prompt zeros followed by valid response positions.
    """
    if isinstance(response_mask, NestedTensor):
        response_offsets = response_mask.offsets().tolist()
        response_lengths = [response_offsets[i + 1] - response_offsets[i] for i in range(len(response_offsets) - 1)]
        batch_size = len(response_lengths)
        response_values = response_mask.values()
    else:
        assert response_attention_mask is not None, "response_attention_mask is required to align padded MTP loss_mask"
        assert not isinstance(response_attention_mask, NestedTensor), (
            "response_attention_mask must be a padded (bs, max_response_len) tensor, got NestedTensor"
        )
        assert response_attention_mask.shape == response_mask.shape, (
            f"response_attention_mask shape {response_attention_mask.shape} "
            f"!= response_mask shape {response_mask.shape}"
        )
        batch_size = response_mask.shape[0]
        response_lengths = response_attention_mask.to(torch.int32).sum(dim=-1).tolist()

    assert len(input_ids_lengths) == batch_size, (
        f"len(input_ids_lengths)={len(input_ids_lengths)} != batch_size={batch_size}"
    )

    pieces = []
    for i in range(batch_size):
        actual_total = int(input_ids_lengths[i])
        actual_response = int(response_lengths[i])
        actual_prompt = actual_total - actual_response
        assert actual_prompt >= 0, (
            f"sample {i}: actual_response={actual_response} > actual_total={actual_total}; "
            "loss_mask cannot be longer than input_ids"
        )
        prompt_pad = torch.zeros(actual_prompt, dtype=response_mask.dtype, device=response_mask.device)
        # Keep the whole valid response span; response_mask may contain internal zeros for tool outputs.
        if isinstance(response_mask, NestedTensor):
            response_piece = response_values[response_offsets[i] : response_offsets[i + 1]]
        else:
            response_piece = response_mask[i, :actual_response]
        full = torch.cat([prompt_pad, response_piece], dim=0)
        assert full.shape[0] == actual_total, (
            f"sample {i}: built loss_mask length {full.shape[0]} != input_ids length {actual_total}"
        )
        pieces.append(full)

    return torch.nested.nested_tensor(pieces, layout=torch.jagged)


def gptmodel_forward_model_engine(
    model,
    input_ids,
    multi_modal_inputs: dict,
    logits_processor=None,
    logits_processor_args: dict = None,
    value_model=False,
    vision_model=False,
    pad_token_id=None,
    data_format: str = "thd",
    mtp_enable_train: bool = False,
    local_cp_size: Optional[int] = None,
    forced_max_seqlen: Optional[int] = None,
    pad_to_length_bucket: Optional[int] = None,
    cp_layout: str = "zigzag",
    router_padding_mask: torch.Tensor | None = None,
    mtp_loss_normalization_factor: float | None = None,
    position_ids: torch.Tensor | None = None,
):
    """Default forward pass for GPT models with optional sequence packing."""

    assert data_format in ["thd", "bshd"], "data_format must be 'thd' or 'bshd'"
    pre_process = unwrap_model(model).pre_process
    post_process = unwrap_model(model).post_process

    use_fp8_padding, fp8_recipe = get_fp8_padding_options(unwrap_model(model).config)

    model_kwargs = {}
    if "pixel_values" in multi_modal_inputs:
        model_kwargs["pixel_values"] = multi_modal_inputs["pixel_values"].to(input_ids.device)
    if "image_grid_thw" in multi_modal_inputs:
        model_kwargs["image_grid_thw"] = multi_modal_inputs["image_grid_thw"].to(input_ids.device)
    if "pixel_values_videos" in multi_modal_inputs:
        model_kwargs["pixel_values_videos"] = multi_modal_inputs["pixel_values_videos"].to(input_ids.device)
    if "video_grid_thw" in multi_modal_inputs:
        model_kwargs["video_grid_thw"] = multi_modal_inputs["video_grid_thw"].to(input_ids.device)

    batch_size = input_ids.shape[0]
    if data_format == "thd":
        attention_mask = None
        thd_kwargs = dict(
            use_fp8_padding=use_fp8_padding,
            fp8_recipe=fp8_recipe,
            local_cp_size=local_cp_size,
            pad_to_length_bucket=pad_to_length_bucket,
            cp_layout=cp_layout,
        )
        # Rank-local THD rows + positions for every model and PP stage: rope LLMs only read positions
        # in MTP; MRoPE positions, when present, are read on every stage.
        input_ids_rmpad, packed_seq_params, position_ids_rmpad = preprocess_thd_engine(
            input_ids, pre_process=True, **thd_kwargs
        )
        if vision_model:
            input_ids_rmpad, attention_mask, position_ids_rmpad = preprocess_vlm_thd_engine(
                model, input_ids, input_ids_rmpad, packed_seq_params, position_ids, pad_token_id, **thd_kwargs
            )

        if mtp_loss_normalization_factor is not None:
            packed_seq_params._verl_mtp_loss_normalization_factor = mtp_loss_normalization_factor
        input_ids_rmpad = input_ids_rmpad.contiguous()

        args = {}
        if mtp_enable_train and post_process:
            # Use input_ids sequence length to ensure label and loss_mask alignment
            input_ids_offsets = input_ids.offsets()
            input_ids_lengths = input_ids_offsets.diff().tolist()
            response_attention_mask = logits_processor_args.get("response_attention_mask", None)

            for k in ["label", "loss_mask"]:
                v = logits_processor_args[k]
                if k == "loss_mask":
                    v = _build_mtp_loss_mask_nested(v, input_ids_lengths, response_attention_mask)
                else:
                    v = _convert_to_nested_tensor(v, input_ids_lengths)
                logits_processor_args[k] = v
                args[k] = preprocess_thd_engine(
                    v,
                    pre_process=True,
                    need_roll=True,
                    use_fp8_padding=use_fp8_padding,
                    fp8_recipe=fp8_recipe,
                    local_cp_size=local_cp_size,
                    pad_to_length_bucket=pad_to_length_bucket,
                    cp_layout=cp_layout,
                )[0]

            model_kwargs["labels"] = args["label"].contiguous()
            model_kwargs["loss_mask"] = args["loss_mask"].contiguous()

        if logits_processor_args and "loss_mask" in logits_processor_args:
            logits_processor_args.pop("loss_mask")
        if logits_processor_args and "response_attention_mask" in logits_processor_args:
            logits_processor_args.pop("response_attention_mask")

        if router_padding_mask is not None:
            model_kwargs["padding_mask"] = router_padding_mask

        output_orig = model(
            input_ids=input_ids_rmpad,
            attention_mask=attention_mask,
            position_ids=position_ids_rmpad,
            packed_seq_params=packed_seq_params,
            **model_kwargs,
        )

        if post_process and logits_processor is not None:
            args = {
                k: preprocess_thd_engine(
                    v,
                    pre_process=True,
                    need_roll=(k == "label"),
                    use_fp8_padding=use_fp8_padding,
                    fp8_recipe=fp8_recipe,
                    local_cp_size=local_cp_size,
                    pad_to_length_bucket=pad_to_length_bucket,
                    cp_layout=cp_layout,
                )[0]
                for k, v in logits_processor_args.items()
            }
            output_dict = logits_processor(output_orig, **args)
            output = {
                k: postprocess_thd_engine(
                    v,
                    packed_seq_params,
                    input_ids,
                    batch_size,
                    post_process=post_process,
                    local_cp_size=local_cp_size,
                    cp_layout=cp_layout,
                )
                for k, v in output_dict.items()
            }
        else:
            output = postprocess_thd_engine(
                output_orig,
                packed_seq_params,
                input_ids,
                batch_size,
                post_process=post_process,
                local_cp_size=local_cp_size,
                cp_layout=cp_layout,
            )
    else:
        """
        data_format: "thd" or "bshd", default is "thd",
        why we need this?
            for some new models, GPT-OSS, the thd format is not supported, so we need to use the bshd format.
        When using the bshd format, we have to add paddings to the input_ids to meet the longest sequence length, 
        so it is recommended to disable dynamic batch size and set batch size to 1
        """
        assert local_cp_size is None, "dynamic_CP is not supported for bshd format"

        input_ids_bshd, attention_mask_bshd, position_ids_bshd = preprocess_bshd_engine(
            input_ids,
            pre_process=pre_process or (post_process and mtp_enable_train),
            use_fp8_padding=use_fp8_padding,
            forced_max_seqlen=forced_max_seqlen,
        )

        if mtp_enable_train and post_process:
            args = {}
            # Use input_ids sequence length to ensure label and loss_mask alignment
            input_ids_offsets = input_ids.offsets()
            input_ids_lengths = input_ids_offsets.diff().tolist()
            response_attention_mask = logits_processor_args.get("response_attention_mask", None)

            for k in ["label", "loss_mask"]:
                v = logits_processor_args[k]
                if k == "loss_mask":
                    v = _build_mtp_loss_mask_nested(v, input_ids_lengths, response_attention_mask)
                else:
                    v = _convert_to_nested_tensor(v, input_ids_lengths)
                logits_processor_args[k] = v
                args[k] = preprocess_bshd_engine(
                    v,
                    pre_process=True,
                    need_roll=True,
                    use_fp8_padding=use_fp8_padding,
                    forced_max_seqlen=forced_max_seqlen,
                )[0]
            model_kwargs["labels"] = args["label"].contiguous()
            model_kwargs["loss_mask"] = args["loss_mask"].contiguous()

        if logits_processor_args and "loss_mask" in logits_processor_args:
            logits_processor_args.pop("loss_mask")
        if logits_processor_args and "response_attention_mask" in logits_processor_args:
            logits_processor_args.pop("response_attention_mask")

        # For VLM model, need to pass bshd format `input_ids` and `attention_mask`.
        if vision_model:
            input_ids_bshd, attention_mask = build_vlm_attn_mask_bshd(
                input_ids, batch_size, pad_token_id, forced_max_seqlen=forced_max_seqlen
            )
        else:
            attention_mask = attention_mask_bshd

        output_orig = model(
            input_ids=input_ids_bshd,
            attention_mask=attention_mask,
            position_ids=None if vision_model else position_ids_bshd,
            **model_kwargs,
        )
        if post_process and logits_processor is not None:
            args = {
                k: preprocess_bshd_engine(
                    v,
                    pre_process=True,
                    need_roll=(k == "label"),
                    use_fp8_padding=use_fp8_padding,
                    forced_max_seqlen=forced_max_seqlen,
                )[0]
                for k, v in logits_processor_args.items()
            }
            output_dict = logits_processor(output_orig, **args)
            output = {
                k: postprocess_bshd_engine(v, attention_mask_bshd, post_process=post_process)
                for k, v in output_dict.items()
            }
        else:
            output = postprocess_bshd_engine(output_orig, attention_mask_bshd, post_process=post_process)

    if value_model and post_process:
        # output = output[..., 0]
        # while using nested tensor, the advanced indexing operation above will result in an error at backward, i.e.
        # ValueError: NestedTensor _nested_select_backward_default(grad_output: t, self: jt_all, dim: any, index: any)
        # so we use `squeeze` to remove the last dimension
        output = output.squeeze(-1)

    return output
