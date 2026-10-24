# Copyright 2024 Bytedance Ltd. and/or its affiliates

# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at

#     http://www.apache.org/licenses/LICENSE-2.0

# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.
"""
Test the MultiTurnSFTDataset implementation
"""

import os
from io import BytesIO
from pathlib import Path

import pandas as pd
import pytest
import torch
from PIL import Image
from tensordict import TensorDict
from torch.utils.data import DistributedSampler
from torchdata.stateful_dataloader import StatefulDataLoader
from transformers import AutoTokenizer
from transformers.utils import get_json_schema

from verl.utils import hf_processor, hf_tokenizer
from verl.utils.dataset.dataset_utils import DatasetPadMode, SFTTensorCollator
from verl.utils.dataset.multiturn_sft_dataset import MultiTurnSFTDataset
from verl.utils.model import extract_multi_modal_inputs

custom_model_prefix = Path("~/models").expanduser().resolve()


@pytest.mark.parametrize(
    "model_path, ignore_input_ids_mismatch",
    [
        (f"{custom_model_prefix}/Qwen/Qwen2.5-0.5B", False),
        (f"{custom_model_prefix}/Qwen/Qwen3-0.6B", True),
        (f"{custom_model_prefix}/Qwen/Qwen3.5-0.8B", False),
    ],
)
def test_multiturn_sft_dataset(model_path: str, ignore_input_ids_mismatch: bool):
    print(f"Starting test... model_path={model_path}, ignore_input_ids_mismatch={ignore_input_ids_mismatch}")
    # Create a temporary parquet file with test data
    test_data = {
        "messages": [
            [
                {"role": "user", "content": "What is 2+2?"},
                {"role": "assistant", "content": "2+2 equals 4."},
                {"role": "tool", "content": "And what is 4+4?"},
                {"role": "assistant", "content": "4+4 equals 8."},
            ],
            [
                # {"role": "system", "content": "You are a powerful assistant."},
                {"role": "user", "content": "Tell me a joke."},
                {"role": "assistant", "content": "Why did the chicken cross the road?"},
                {"role": "tool", "content": "Why?"},
                {"role": "assistant", "content": "To get to the other side!"},
            ],
        ]
    }

    # Create test directory if it doesn't exist
    os.makedirs("test_data", exist_ok=True)
    test_file = "test_data/test.parquet"

    # Save test data to parquet
    df = pd.DataFrame(test_data)
    df.to_parquet(test_file)

    # Initialize tokenizer and dataset
    tokenizer = hf_tokenizer(model_path)
    # processor = hf_processor(model_path)
    processor = None
    config = {
        "max_length": 512,
        "truncation": "error",
        "multiturn": {"messages_key": "messages"},
        "ignore_input_ids_mismatch": ignore_input_ids_mismatch,
    }
    dataset = MultiTurnSFTDataset(parquet_files=test_file, tokenizer=tokenizer, processor=processor, config=config)

    # Test 1: Dataset Length
    assert len(dataset) == 2, f"Expected dataset length 2, got {len(dataset)}"

    # Get items for testing
    item0 = dataset[0]  # Math conversation
    item1 = dataset[1]  # Joke conversation

    # Test 2: Required Keys and Types
    required_keys = ["input_ids", "attention_mask", "position_ids", "loss_mask"]
    for key in required_keys:
        assert key in item0, f"Missing key {key} in dataset item"
        assert isinstance(item0[key], torch.Tensor), f"Expected torch.Tensor for {key}"
        assert item0[key].dtype == torch.long, f"Expected torch.long for {key}, got {item0[key].dtype}"

    # Test 3: Shape Consistency
    assert item0["loss_mask"].shape == item0["input_ids"].shape, "Loss mask shape doesn't match input_ids shape"
    assert item0["attention_mask"].shape == item0["input_ids"].shape, (
        "Attention mask shape doesn't match input_ids shape"
    )
    assert item0["position_ids"].shape == item0["input_ids"].shape, "Position IDs shape doesn't match input_ids shape"

    # Test 4: Loss Mask Pattern - Math Conversation
    loss_mask0 = item0["loss_mask"]
    input_ids0 = item0["input_ids"]

    # Find assistant response positions
    assistant_positions0 = torch.where(loss_mask0 == 1)[0]
    assert len(assistant_positions0) > 0, "No assistant positions found in loss mask"

    # Decode and verify assistant responses
    assistant_text0 = tokenizer.decode(input_ids0[loss_mask0 == 1])
    print(f"Math conversation assistant text: {assistant_text0}")
    assert "2+2 equals 4" in assistant_text0, "First assistant response not found"
    assert "4+4 equals 8" in assistant_text0, "Second assistant response not found"

    # Test 5: Loss Mask Pattern - Joke Conversation
    loss_mask1 = item1["loss_mask"]
    input_ids1 = item1["input_ids"]

    # Find assistant response positions
    assistant_positions1 = torch.where(loss_mask1 == 1)[0]
    assert len(assistant_positions1) > 0, "No assistant positions found in loss mask"

    # Decode and verify assistant responses
    assistant_text1 = tokenizer.decode(input_ids1[loss_mask1 == 1])
    print(f"Joke conversation assistant text: {assistant_text1}")
    assert "chicken cross the road" in assistant_text1, "First assistant response not found"
    assert "other side" in assistant_text1, "Second assistant response not found"

    # Test 6: Attention Mask Pattern
    attention_mask0 = item0["attention_mask"]
    sequence_length = torch.sum(attention_mask0)
    assert sequence_length > 0, "No tokens marked as attended in attention mask"
    assert torch.all(attention_mask0[:sequence_length] == 1), "Incorrect attention mask pattern"
    if sequence_length < len(attention_mask0):
        assert torch.all(attention_mask0[sequence_length:] == 0), "Padding not properly masked"

    # Test 7: Position IDs Pattern
    position_ids0 = item0["position_ids"]
    assert torch.equal(position_ids0[:sequence_length], torch.arange(sequence_length)), (
        "Position IDs not sequential for non-padded tokens"
    )
    if sequence_length < len(position_ids0):
        assert torch.all(position_ids0[sequence_length:] == 0), "Padding position IDs not zero"

    # Test 8: Verify loss mask for assistant responses
    # Get the full conversation text
    full_text = tokenizer.decode(input_ids0)
    print(f"\nFull conversation text:\n{full_text}")

    # Get the assistant responses
    assistant_text = tokenizer.decode(input_ids0[loss_mask0 == 1])
    print(f"\nAssistant responses (from loss mask):\n{assistant_text}")

    # Verify that loss mask is set for all assistant responses
    for msg in test_data["messages"][0]:  # First conversation
        if msg["role"] == "assistant":
            # The content should appear in the masked text
            assert msg["content"] in assistant_text, f"Assistant message '{msg['content']}' not found in masked text"

            # The content should NOT appear in the non-masked text
            non_assistant_text = tokenizer.decode(input_ids0[loss_mask0 == 0])
            assert msg["content"] not in non_assistant_text, (
                f"Assistant message '{msg['content']}' found in non-assistant text"
            )

    # Test 9: Verify non-assistant parts have loss_mask=0
    # Get non-assistant text
    non_assistant_text = tokenizer.decode(input_ids0[loss_mask0 == 0])
    print(f"\nNon-assistant text (from loss mask):\n{non_assistant_text}")

    # Verify that system and user messages are in the non-assistant text
    for msg in test_data["messages"][0]:  # First conversation
        if msg["role"] in ["system", "user"]:
            assert msg["content"] in non_assistant_text, (
                f"{msg['role'].title()} message '{msg['content']}' not found in non-assistant text"
            )

            # And verify they're NOT in the assistant text
            assert msg["content"] not in assistant_text, (
                f"{msg['role'].title()} message '{msg['content']}' found in assistant text"
            )

    # Test 10: Verify padding behavior
    padding_config = {
        "max_length": 1024,
        "truncation": "error",
        "multiturn": {"messages_key": "messages"},
        "ignore_input_ids_mismatch": ignore_input_ids_mismatch,
    }
    small_dataset = MultiTurnSFTDataset(
        parquet_files=test_file, tokenizer=tokenizer, processor=processor, config=padding_config
    )
    padded_item = small_dataset[0]

    # Get actual sequence length (before padding)
    actual_length = torch.sum(padded_item["attention_mask"])

    # Verify padding tokens
    assert torch.all(padded_item["input_ids"][actual_length:] == tokenizer.pad_token_id), (
        "Padding tokens not set correctly"
    )
    assert torch.all(padded_item["attention_mask"][actual_length:] == 0), "Attention mask not set correctly for padding"
    assert torch.all(padded_item["loss_mask"][actual_length:] == 0), "Loss mask not set correctly for padding"

    # test no-padding
    config = {
        "max_length": 512,
        "truncation": "error",
        "multiturn": {"messages_key": "messages"},
        "pad_mode": "no_padding",
        "ignore_input_ids_mismatch": ignore_input_ids_mismatch,
    }
    dataset = MultiTurnSFTDataset(parquet_files=test_file, tokenizer=tokenizer, processor=processor, config=config)

    item0 = dataset[0]

    # Verify that the output contains expected keys for no-padding mode
    required_keys = ["input_ids", "position_ids", "loss_mask"]
    for key in required_keys:
        assert key in item0, f"Missing key {key} in no-padding mode dataset item"
        assert isinstance(item0[key], torch.Tensor), f"Expected torch.Tensor for {key} in no-padding mode"

    # make sure assistant_text matches with expected
    assistant_text = tokenizer.decode(item0["input_ids"][item0["loss_mask"] == 1])
    assert assistant_text == "2+2 equals 4.<|im_end|>\n4+4 equals 8.<|im_end|>\n"

    print("All tests passed!")
    print("Starting test...")


@pytest.mark.parametrize(
    "model_path, apply_chat_template_kwargs",
    [
        (f"{custom_model_prefix}/openai/gpt-oss-20b", {"model_identity": "You are a helpful assistant."}),
    ],
)
def test_multiturn_sft_dataset_with_chat_template_kwargs(model_path: str, apply_chat_template_kwargs: dict):
    """Test that custom apply_chat_template_kwargs are forwarded to system prompt
    measurement so the loss mask is not shifted when kwargs change tokenization.

    Some chat templates embed configurable fields (e.g. model_identity) in the
    system prompt. If these kwargs are not forwarded to system prompt length
    measurement, the per-turn strip length is wrong, causing role markers to be
    removed and the loss mask to shift.
    """
    test_data = {
        "messages": [
            [
                {"role": "user", "content": "What is 2+2?"},
                {"role": "assistant", "content": "2+2 equals 4."},
            ],
            [
                {"role": "user", "content": "Tell me a joke."},
                {"role": "assistant", "content": "Why did the chicken cross the road?"},
            ],
        ]
    }

    os.makedirs("test_data", exist_ok=True)
    test_file = "test_data/test_kwargs.parquet"
    df = pd.DataFrame(test_data)
    df.to_parquet(test_file)

    tokenizer = hf_tokenizer(model_path)

    config = {
        "max_length": 1024,
        "truncation": "error",
        "pad_mode": "no_padding",
        "apply_chat_template_kwargs": apply_chat_template_kwargs,
    }
    dataset = MultiTurnSFTDataset(parquet_files=test_file, tokenizer=tokenizer, processor=None, config=config)

    for idx in range(len(dataset)):
        item = dataset[idx]
        input_ids = item["input_ids"]
        loss_mask = item["loss_mask"]

        assistant_text = tokenizer.decode(input_ids[loss_mask == 1])
        non_assistant_text = tokenizer.decode(input_ids[loss_mask == 0])

        for msg in test_data["messages"][idx]:
            if msg["role"] == "assistant":
                assert msg["content"] in assistant_text, (
                    f"Assistant message '{msg['content']}' not found in masked text. "
                    f"This may indicate system prompt length mismatch when using "
                    f"custom chat_template_kwargs."
                )
                assert msg["content"] not in non_assistant_text, (
                    f"Assistant message '{msg['content']}' found in non-assistant text"
                )
            elif msg["role"] in ["system", "user"]:
                assert msg["content"] in non_assistant_text, (
                    f"{msg['role'].title()} message '{msg['content']}' not found in non-assistant text"
                )
                assert msg["content"] not in assistant_text, (
                    f"{msg['role'].title()} message '{msg['content']}' found in assistant text"
                )

    print("All chat_template_kwargs tests passed!")


def generate_image(description: str, size: str = "256x256"):
    """Generate a simple image based on description.

    Args:
        description: The description of the image to generate.
        size: The size of the image. Defaults to "256x256". (choices: ["256x256", "512x512"])

    Returns:
        A generated image
    """
    ...


@pytest.fixture
def vlm_data_file():
    test_data = [
        # sample 0: single turn with image input
        {
            "messages": [
                {
                    "role": "user",
                    "content": "<image>Describe this image.",
                },
                {
                    "role": "assistant",
                    "content": "The image is a red square.",
                },
            ],
            "images": [Image.new("RGB", (300, 300), color="red")],
            "tools": [],
        },
        # sample 1: single turn with multiple images input
        {
            "messages": [
                {
                    "role": "user",
                    "content": "<image><image>Compare these images.",
                },
                {
                    "role": "assistant",
                    "content": "The first image is a red square and the second image is a green square.",
                },
            ],
            "images": [Image.new("RGB", (100, 100), color="red"), Image.new("RGB", (100, 300), color="green")],
            "tools": [],
        },
        # sample 2: multi turn with image input and tool generated image
        {
            "messages": [
                {
                    "role": "user",
                    "content": "<image>Describe this image.",
                },
                {
                    "role": "assistant",
                    "content": "Let's generate a zoom-in image.",
                    "tool_calls": [
                        {
                            "function": {"arguments": {"bbox_2d": "[0, 1, 2, 4]"}, "name": "image_zoom_in_tool"},
                            "type": "function",
                        }
                    ],
                },
                {
                    "role": "tool",
                    "content": "<image>Generated image.",
                },
                {"role": "assistant", "content": "The zoom-in image is a red square."},
            ],
            "images": [Image.new("RGB", (300, 500), color="red"), Image.new("RGB", (100, 100), color="red")],
            "tools": [get_json_schema(generate_image)],
        },
        # sample 3: single turn without image input
        {
            "messages": [
                {"role": "user", "content": "How is the weather today?"},
                {"role": "assistant", "content": "The weather is sunny."},
            ],
            "images": [],
            "tools": [],
        },
    ]

    # Create test directory if it doesn't exist
    os.makedirs("test_data", exist_ok=True)
    test_file = "test_data/test_vlm.parquet"

    # Save test data to parquet
    df = pd.DataFrame(test_data)

    def serialize_image(img):
        if isinstance(img, Image.Image):
            img_byte_arr = BytesIO()
            img.save(img_byte_arr, format="PNG")
            return {"bytes": img_byte_arr.getvalue()}
        return img

    df["images"] = df["images"].apply(lambda x: [serialize_image(img) for img in x])

    df.to_parquet(test_file)
    return test_file


@pytest.mark.parametrize(
    "model_path",
    [
        f"{custom_model_prefix}/Qwen/Qwen3-VL-2B-Instruct",
    ],
)
def test_multiturn_sft_vlm_dataset_on_cpu(model_path, vlm_data_file):
    df = pd.read_parquet(vlm_data_file)
    tokenizer = hf_tokenizer(model_path)
    processor = hf_processor(model_path)
    config = {"max_length": 1024, "pad_mode": "no_padding", "truncation": "error", "messages_key": "messages"}
    dataset = MultiTurnSFTDataset(parquet_files=vlm_data_file, tokenizer=tokenizer, processor=processor, config=config)
    assert dataset.pad_mode == DatasetPadMode.NO_PADDING

    for i in range(len(dataset)):
        item = dataset[i]
        input_ids = item["input_ids"]
        loss_mask = item["loss_mask"]
        position_ids = item["position_ids"]
        pixel_values = item.get("multi_modal_inputs", {}).get("pixel_values")
        image_grid_thw = item.get("multi_modal_inputs", {}).get("image_grid_thw")

        assert input_ids.shape == loss_mask.shape, "Shapes of input_ids and loss_mask must be equal"
        assert position_ids.dim() == 2, "position_ids must be 2-dimensional"
        assert position_ids.shape[0] == 4, f"position_ids[0] should be 4: {position_ids[0]}"
        assert position_ids.shape[1] == input_ids.shape[0]

        # 1. verify input_ids without assistant text
        text = tokenizer.decode(input_ids[loss_mask == 0], skip_special_tokens=True)
        print(f"Text without assistant: {repr(text)}")
        for message in df["messages"][i]:
            if message["role"] != "assistant":
                content = message["content"].replace("<image>", "")
                assert content in text, f"user/tool text should be in the input_ids: {text}"

        # 2. verify input_ids with assistant text
        text = tokenizer.decode(input_ids[loss_mask == 1], skip_special_tokens=True)
        print(f"Text with assistant: {repr(text)}")
        for message in df["messages"][i]:
            if message["role"] == "assistant":
                assert message["content"] in text, f"Assistant text should be in the input_ids: {text}"
                assert "assistant" not in text, f"Assistant token should not be in the input_ids: {text}"

        # 3. verify image token match with image_grid_thw
        if len(df["images"][i]) > 0:
            patch_size = processor.image_processor.patch_size
            temporal_patch_size = processor.image_processor.temporal_patch_size
            merge_size = processor.image_processor.merge_size
            num_patches = image_grid_thw.prod(dim=1).sum()
            assert image_grid_thw.shape == (len(df["images"][i]), 3), (
                f"image_grid_thw: {image_grid_thw.shape} should have shape ({len(df['images'][i])}, 3)"
            )
            assert pixel_values.shape == (num_patches, 3 * temporal_patch_size * patch_size * patch_size), (
                f"pixel_values: {pixel_values.shape} should have shape ({num_patches}, {3 * patch_size * patch_size})"
            )
            assert (input_ids == processor.image_token_id).sum() == num_patches // (merge_size**2)
        else:
            assert pixel_values is None, "pixel_values should be None when no image is provided"
            assert image_grid_thw is None, "image_grid_thw should be None when no image is provided"


@pytest.mark.parametrize(
    "model_path",
    [
        f"{custom_model_prefix}/Qwen/Qwen3-VL-2B-Instruct",
    ],
)
def test_multiturn_sft_vlm_dataloader_on_cpu(model_path, vlm_data_file):
    df = pd.read_parquet(vlm_data_file)
    tokenizer = hf_tokenizer(model_path)
    processor = hf_processor(model_path)
    config = {"max_length": 1024, "pad_mode": "no_padding", "truncation": "error", "messages_key": "messages"}
    dataset = MultiTurnSFTDataset(parquet_files=vlm_data_file, tokenizer=tokenizer, processor=processor, config=config)
    assert dataset.pad_mode == DatasetPadMode.NO_PADDING

    collate_fn = SFTTensorCollator(DatasetPadMode.NO_PADDING)
    sampler = DistributedSampler(dataset, shuffle=False, num_replicas=1, rank=0, drop_last=True)
    batch_size = 2
    dataloader = StatefulDataLoader(
        dataset=dataset,
        batch_size=batch_size,
        sampler=sampler,
        collate_fn=collate_fn,
        num_workers=0,
        pin_memory=False,
        drop_last=True,
    )

    for i, batch in enumerate(dataloader):
        # 1. verify input_ids, loss_mask
        input_ids = batch["input_ids"]
        loss_mask = batch["loss_mask"]
        assert input_ids.is_nested, "input_ids should be a nested tensor"
        assert loss_mask.is_nested, "loss_mask should be a nested tensor"
        assert input_ids.shape[0] == loss_mask.shape[0] == batch_size, "Shapes of input_ids, loss_mask must be equal"

        # 2. verify position_ids: (bs, 4, seq_len)
        position_ids = batch["position_ids"]
        assert position_ids.is_nested, "position_ids should be a nested tensor"
        assert position_ids.dim() == 3, "position_ids must be 3-dimensional"
        assert position_ids.shape[0] == batch_size
        values = position_ids.values()
        assert values.shape == (4, len(input_ids.values()))

        # 3. verify multi-modal data
        td = TensorDict(**batch, batch_size=batch_size)
        multi_modal_inputs = extract_multi_modal_inputs(td["multi_modal_inputs"])
        pixel_values = multi_modal_inputs["pixel_values"]
        image_grid_thw = multi_modal_inputs["image_grid_thw"]

        num_images = sum([len(images) for images in df["images"][i * batch_size : (i + 1) * batch_size]])
        assert image_grid_thw.shape == (num_images, 3), (
            f"image_grid_thw: {image_grid_thw.shape} should have shape ({num_images}, 3)"
        )
        patch_size = processor.image_processor.patch_size
        temporal_patch_size = processor.image_processor.temporal_patch_size
        num_patches = image_grid_thw.prod(dim=1).sum()
        assert pixel_values.shape[0] == num_patches, (
            f"pixel_values: {pixel_values.shape} should have shape "
            f"({num_patches}, 3 * {temporal_patch_size} * {patch_size} * {patch_size})"
        )


@pytest.mark.parametrize("model_path", ["Qwen/Qwen2.5-0.5B-Instruct"])
def test_multiturn_sft_dataset_trainable_flag(model_path: str):
    """Test the trainable flag functionality for masking assistant messages.

    This test verifies that:
    1. By default (trainable not specified), all assistant messages have loss_mask=1
    2. When trainable=False, the assistant message has loss_mask=0
    3. When trainable=True, the assistant message has loss_mask=1

    This feature is useful for:
    - Filtering low-quality trajectories
    - Selective training on specific assistant responses
    - Ignoring intermediate steps in long agent trajectories
    """
    print(f"Starting test... model_path={model_path}")

    # Test data with trainable flag
    test_data = {
        "messages": [
            # Case 1: Default behavior (no trainable flag)
            [
                {"role": "user", "content": "Hello"},
                {"role": "assistant", "content": "Hi there!"},
            ],
            # Case 2: trainable=False - should be masked
            [
                {"role": "user", "content": "What is 2+2?"},
                {"role": "assistant", "content": "2+2 equals 5.", "trainable": False},  # Wrong answer, masked
                {"role": "user", "content": "That's wrong."},
                {"role": "assistant", "content": "Sorry, 2+2 equals 4.", "trainable": True},  # Corrected answer
            ],
            # Case 3: trainable=True explicitly
            [
                {"role": "user", "content": "Tell me a joke"},
                {"role": "assistant", "content": "Why did the chicken?", "trainable": True},
                {"role": "user", "content": "Why?"},
                {"role": "assistant", "content": "To get to the other side!", "trainable": True},
            ],
            # Case 4: Mix of trainable and non-trainable
            [
                {"role": "user", "content": "Calculate 1+1"},
                {"role": "assistant", "content": "1+1=3", "trainable": False},
                {"role": "user", "content": "No"},
                {"role": "assistant", "content": "1+1=2"},
            ],
        ]
    }

    # Create test directory if it doesn't exist
    os.makedirs("test_data", exist_ok=True)
    test_file = "test_data/test_trainable.parquet"

    # Save test data to parquet
    df = pd.DataFrame(test_data)
    df.to_parquet(test_file)

    # Initialize tokenizer and dataset
    tokenizer = AutoTokenizer.from_pretrained(model_path)
    config = {
        "max_length": 512,
        "truncation": "error",
        "multiturn": {"messages_key": "messages"},
    }
    dataset = MultiTurnSFTDataset(parquet_files=test_file, tokenizer=tokenizer, config=config)

    # Test Case 1: Default behavior (no trainable flag)
    item0 = dataset[0]
    loss_mask0 = item0["loss_mask"]
    assistant_positions0 = torch.where(loss_mask0 == 1)[0]
    assert len(assistant_positions0) > 0, "Default: assistant should have loss_mask=1"
    print(f"Case 1 (default): assistant loss_mask sum = {loss_mask0.sum().item()}")

    # Test Case 2: trainable=False should mask the message
    item1 = dataset[1]
    loss_mask1 = item1["loss_mask"]
    input_ids1 = item1["input_ids"]

    # Decode to verify which assistant messages are present
    assistant_text1 = tokenizer.decode(input_ids1[loss_mask1 == 1])
    print(f"Case 2 (trainable=False): assistant text = '{assistant_text1}'")

    # The second assistant message (with trainable=False) should NOT be in the loss
    assert "2+2 equals 5" not in assistant_text1, "trainable=False message should be masked"
    assert "2+2 equals 4" in assistant_text1, "trainable=True message should be trained"
    print("Case 2: loss_mask correctly masks trainable=False message")

    # Test Case 3: trainable=True explicitly
    item2 = dataset[2]
    loss_mask2 = item2["loss_mask"]
    input_ids2 = item2["input_ids"]

    assistant_text2 = tokenizer.decode(input_ids2[loss_mask2 == 1])
    print(f"Case 3 (trainable=True): assistant text = '{assistant_text2}'")

    # Both should be trained
    assert "chicken" in assistant_text2, "First trainable=True message should be trained"
    assert "other side" in assistant_text2, "Second trainable=True message should be trained"
    print("Case 3: loss_mask correctly includes trainable=True messages")

    # Test Case 4: Mix of trainable and non-trainable (default is trainable=True for assistant)
    item3 = dataset[3]
    loss_mask3 = item3["loss_mask"]
    input_ids3 = item3["input_ids"]

    assistant_text3 = tokenizer.decode(input_ids3[loss_mask3 == 1])
    print(f"Case 4 (mixed): assistant text = '{assistant_text3}'")

    # First assistant has trainable=False, should be masked
    # Second assistant has no trainable flag, default is trainable
    assert "1+1=3" not in assistant_text3, "trainable=False message should be masked"
    assert "1+1=2" in assistant_text3, "Default trainable message should be trained"
    print("Case 4: loss_mask correctly handles mixed trainable flags")

    print("All test cases passed!")

    # Cleanup
    import shutil

    shutil.rmtree("test_data", ignore_errors=True)
