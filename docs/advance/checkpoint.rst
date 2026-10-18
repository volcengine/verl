.. _checkpoint-page:

Using Checkpoints to Support Fault Tolerance Training
=====================================================

Last updated: 08/24/2026.

There could be training errors or machine failure during the whole RLHF training process, 
so it is recommended to enable checkpoints to minimize your loss.

The API Interface has already been listed in :ref:`config-explain-page`,
and we will not repeat them. But there are still some technique details
we hope to clarify.

The ``checkpoint.save_contents`` / ``checkpoint.load_contents`` field accepts any combination of
``model``, ``optimizer``, ``extra`` and ``hf_model``. The semantics are aligned between FSDP and
Megatron:

- ``model`` -- the framework-native model state. For **FSDP** this is the per-rank sharded state;
  for **Megatron** this follows whether the engine provides a megatron-bridge ``bridge`` and
  ``use_dist_checkpointing``: HF weights under ``model/huggingface/`` when the HF path is active,
  Megatron shards under ``model/dist_ckpt/`` when ``use_dist_checkpointing=True``, or **both**
  when a ``bridge`` is present and dist shards are also enabled for the ``model`` slot.
- ``optimizer`` -- the optimizer state (sharded for both FSDP and Megatron).
- ``extra`` -- LR scheduler state, RNG states, and (for Megatron) the serialised
  ``TransformerConfig``.
- ``hf_model`` -- the full model in HuggingFace format. **Megatron requires a non-``None`` megatron-bridge
  ``bridge``** (the checkpoint manager checks ``bridge``, not a separate flag) whenever ``hf_model``
  appears in ``save_contents`` or ``load_contents``. In practice the engine supplies the bridge when
  megatron-bridge is enabled (``use_mbridge=True`` in YAML). If the checkpoint also uses
  ``use_dist_checkpointing=True`` for the ``model`` slot, HF export (``model/huggingface/``) is
  written **in addition to** Megatron shards under ``model/dist_ckpt/``. When only the HF ``model``
  path is used (no dist shards for weights), ``model`` and ``hf_model`` refer to the same HF tree
  and are deduplicated (saved once).

.. note::

    For FSDP, ``checkpoint.save_contents`` other than ``hf_model`` are binded together to save and
    load. We recommend to include ``model``, ``optimizer`` and ``extra`` all.

Checkpoint Callback
-------------------

Set ``trainer.checkpoint_callback_class`` to the fully qualified class name of a
``verl.trainer.ppo.checkpoint_callback.CheckpointCallback`` subclass to run custom
code after each trainer checkpoint save (v1 trainer, ``trainer.use_v1=true``) —
for example uploading checkpoints to object storage, registering them in a model
registry, or triggering evaluations.
The interface mirrors the ``on_save`` event of the HuggingFace ``transformers``
``TrainerCallback``:

.. code:: yaml

    trainer:
      checkpoint_callback_class: my_pkg.callbacks.MyCheckpointCallback

The class must be importable on the driver. It is instantiated once with the full
trainer config (``cls(config=config)``), and its ``on_save`` hook is invoked with
keyword arguments:

.. code:: python

    from verl.trainer.ppo.checkpoint_callback import CheckpointCallback

    class MyCheckpointCallback(CheckpointCallback):
        def on_save(self, trainer, global_step, checkpoint_dir, async_save=False, **kwargs):
            upload_to_my_storage(checkpoint_dir, step=global_step)

Hook semantics:

- ``on_save`` is called after the save of a ``global_step_{N}`` directory and
  only fires when the save path completed without raising. With
  ``async_save=True`` (Megatron asynchronous checkpointing), worker-side writes
  may still be in flight when ``on_save`` fires and
  ``latest_checkpointed_iteration.txt`` has not been written, so do not assume
  the checkpoint is durable yet.
- The hook runs only on the driver process, after the worker-group RPCs.
  Per-rank hooks inside the FSDP/Megatron checkpoint managers are not covered.
- Exceptions raised by the hook propagate and abort training. Wrap the hook
  body in ``try/except`` for best-effort semantics.

Checkpoint Saving Directory Structure
-------------------------------------

Commonly, we use the ``default_local_dir`` declared in ``ppo_trainer.yaml`` or ``ppo_megatron_trainer.yml``
to work as preffix when saving checkpoints, which is ``checkpoints/${trainer.project_name}/${trainer.experiment_name}``.

So the inner checkpoint structure of **FSDP** is like:

.. code::

    checkpoints/${trainer.project_name}/${trainer.experiment_name}
    ├── global_steps_${i}
    │   ├── actor
    │   │   ├── huggingface      # default save config and tokenizer, save huggingface model if include ``hf_model`` in checkpoint.contents
    │   │   └── fsdp_config.json # FSDP config file, including world_size and fsdp version
    │   │   ├── model_world_size_{self.world_size}_rank_{self.rank}.pt
    │   │   ├── optim_world_size_{self.world_size}_rank_{self.rank}.pt
    │   │   └── extra_state_world_size_{self.world_size}_rank_{self.rank}.pt
    │   ├── critic
    │   │   ├── huggingface
    │   │   └── fsdp_config.json
    │   │   ├── model_world_size_{self.world_size}_rank_{self.rank}.pt
    │   │   ├── optim_world_size_{self.world_size}_rank_{self.rank}.pt
    │   │   └── extra_state_world_size_{self.world_size}_rank_{self.rank}.pt
    └── latest_checkpointed_iteration.txt

All model shards, optimizers and extra states are stored together, in a sharded and distributed way.

LoRA-only Checkpoints
---------------------

When the model is trained with LoRA adapters, set
``checkpoint.save_lora_only = True`` to save only the adapter weights
instead of the full model state dict. This reduces checkpoint size
from ~54 GiB to ~150 MiB for a 27B model.

- **Save**: Only parameter keys containing ``lora_`` or ``.adapter_`` are
  kept; all base-model weights are excluded.
- **Load**: The checkpoint manager detects LoRA-only checkpoints
  automatically by checking whether all keys are adapter keys.
  ``load_state_dict(strict=False)`` is used, followed by validation
  that no unexpected keys exist.
- **Backward compatibility**: Full checkpoints (all weights) are loaded
  with ``strict=True`` as before; the presence of ``save_lora_only``
  does not affect them.

The LoRA-only checkpoint is written to the same ``model_*.pt`` shard
file as a full checkpoint, so the directory layout is identical.

While **Megatron** current checkpoint structure (layout schema v2) is:

.. code::

    checkpoints/${trainer.project_name}/${trainer.experiment_name}
    ├── global_steps_${i}
    │   ├── actor
    │   │   ├── ckpt_contents.json       # manifest mapping each saved content (model, optimizer, …) to its on-disk path; see "Locating saved contents" below
    │   │   ├── transformer_config.json  # serialised Megatron TransformerConfig (written when ``extra`` is in save_contents)
    │   │   ├── model
    │   │   │   ├── huggingface          # HF weights + config + tokenizer (megatron-bridge ``bridge`` + ``model`` / ``hf_model`` in save_contents)
    │   │   │   └── dist_ckpt            # Megatron model shards when ``use_dist_checkpointing``; PEFT adapter shards may live here with megatron-bridge
    │   │   ├── optimizer
    │   │   │   └── dist_ckpt            # optimizer + lr_scheduler shards (written when ``optimizer`` is in save_contents)
    │   │   └── extra
    │   │       └── dist_ckpt            # rng_state shards (written when ``extra`` is in save_contents)
    │   └── critic                       # same layout as actor
    └── latest_checkpointed_iteration.txt

.. note::

    **Migrating pre-v2 checkpoints.** Older verl releases produced a flatter
    layout with a single root-level ``dist_ckpt/`` directory (containing the
    optimizer, rng, and optionally model shards) and a root-level
    ``huggingface/`` directory.  The v2 loader rejects that layout at
    ``load_checkpoint`` time with a clear error.  Convert an old checkpoint
    in place with::

        python scripts/migrate_megatron_checkpoint_layout.py \
            --checkpoint /path/to/global_step_N/actor

    or migrate every step under a run with
    ``--checkpoint-root /path/to/run --all-steps``.  The migration defaults
    to hardlinking the old ``dist_ckpt`` data into the new
    ``model/optimizer/extra`` subdirectories, so it is fast and does not
    duplicate disk usage.

.. tip::

    **Locating saved contents.** Every Megatron checkpoint directory contains a
    ``ckpt_contents.json`` manifest at its root. To find where a specific piece of
    the checkpoint lives (HF weights, optimizer shards, tokenizer, PEFT adapters,
    …), open ``ckpt_contents.json`` and look up the logical name under the
    ``contents`` map — each entry has a ``path`` field (relative to the checkpoint
    directory) and a ``format`` field. The manifest is written last during the
    save, so its presence also indicates a fully-complete checkpoint. A typical
    manifest looks like:

    .. code:: json

        {
          "schema_version": 2,
          "framework": "megatron",
          "role": "actor",
          "arch": "Qwen3ForCausalLM",
          "global_step": 100,
          "world_size": 8,
          "backend": {"has_bridge": true, "use_dist_checkpointing": false, "peft": false},
          "save_contents": ["model", "optimizer", "extra"],
          "contents": {
            "model":              {"path": "model/huggingface",    "format": "huggingface", "backend": "megatron-bridge"},
            "optimizer":          {"path": "optimizer/dist_ckpt",  "format": "megatron_dist_checkpoint"},
            "lr_scheduler":       {"path": "optimizer/dist_ckpt",  "format": "megatron_dist_checkpoint", "key": "lr_scheduler"},
            "rng_state":          {"path": "extra/dist_ckpt",      "format": "megatron_dist_checkpoint", "key": "rng_state"},
            "transformer_config": {"path": "transformer_config.json", "format": "json"},
            "hf_config":          {"path": "model/huggingface",    "format": "huggingface"},
            "tokenizer":          {"path": "model/huggingface",    "format": "huggingface"}
          },
          "directories": {
            "model/huggingface":   "HuggingFace-format artifacts written via megatron-bridge: model weights, config.json, …",
            "optimizer/dist_ckpt": "Megatron dist_checkpointing shards for the optimizer state …",
            "extra/dist_ckpt":     "Megatron dist_checkpointing shards for extra state (rng_state)."
          },
          "saved_any_dist_ckpt": true
        }

Megatron Checkpoint Manager Backends
------------------------------------

Megatron model weights are controlled by two booleans on
``actor_rollout_ref.actor.megatron`` (and the symmetric ``critic`` / ``ref`` keys):

- **``use_mbridge`` (default ``True``)** -- when enabled, the Megatron engine builds the Megatron-Bridge
  instance passed into ``MegatronCheckpointManager`` as ``bridge``, which is
  **required** for HuggingFace-format model weights under
  ``global_step_${i}/${role}/model/huggingface/``. The manager itself only checks ``bridge is not
  None`` for ``hf_model`` (and other HF model paths).

- **``use_dist_checkpointing``** -- when ``True``, Megatron ``dist_checkpointing`` shards for the
  ``model`` slot are written/read under ``global_step_${i}/${role}/model/dist_ckpt/``.

The two flags are **independent**: both may be ``True`` to persist resume-friendly shards **and**
an HF tree in the same step. Setting ``use_mbridge=False`` disables HF export/load via megatron-bridge;
``use_dist_checkpointing=False`` disables Megatron model shards for the ``model`` slot (unless
PEFT still needs adapter shards under ``model/dist_ckpt/``).

Optimizer + LR-scheduler (``optimizer/dist_ckpt/``) and RNG state (``extra/dist_ckpt/``) always
go through ``dist_checkpointing`` into their own sibling directories.

.. note::

    Prefer tuning ``use_mbridge`` and ``use_dist_checkpointing`` explicitly. Avoid relying on
    informal equivalences between the two; hybrid checkpoints need both enabled.

The diagram below (from `RFC #5630
<https://github.com/verl-project/verl/issues/5630>`_) summarises how each combination of backend
and ``save_contents`` entry is resolved:

.. image:: https://github.com/user-attachments/assets/6036822e-9d8a-4c1f-bbcc-a15dcb584c1b
   :alt: Megatron checkpoint manager backend × save_contents behaviour
   :align: center

In tabular form:

+-------------------------------------+---------------+--------------------------------------------------------+
| Flags (megatron-bridge / dist_ckpt) | save_contents | Behaviour                                              |
+=====================================+===============+========================================================+
| megatron-bridge only                | ``model``     | HF weights under ``model/huggingface/``.               |
+-------------------------------------+---------------+--------------------------------------------------------+
| megatron-bridge only                | ``hf_model``  | Same (HF tree); ``model`` / ``hf_model`` deduplicated. |
+-------------------------------------+---------------+--------------------------------------------------------+
| megatron-bridge only                | both          | Same HF checkpoint saved **once** (deduplicated).      |
+-------------------------------------+---------------+--------------------------------------------------------+
| dist_ckpt only                      | ``model``     | Sharded weights under ``model/dist_ckpt/``.            |
+-------------------------------------+---------------+--------------------------------------------------------+
| dist_ckpt only                      | ``hf_model``  | **Error** -- ``hf_model`` needs a ``bridge``           |
|                                     |               | (enable megatron-bridge in engine).                    |
+-------------------------------------+---------------+--------------------------------------------------------+
| megatron-bridge + dist_ckpt         | ``model``     | Sharded weights under ``model/dist_ckpt/`` only (no HF |
|                                     |               | weight export unless ``hf_model`` is also listed).     |
+-------------------------------------+---------------+--------------------------------------------------------+
| megatron-bridge + dist_ckpt         | ``model`` +   | Megatron shards **and** HF export (two on-disk trees). |
|                                     | ``hf_model``  |                                                        |
+-------------------------------------+---------------+--------------------------------------------------------+

In all rows above, ``optimizer`` and ``extra`` (when listed in ``save_contents``) are saved through
``dist_checkpointing`` into their own directories -- ``optimizer/dist_ckpt/`` and
``extra/dist_ckpt/``.  PEFT/LoRA adapter shards are written into ``model/dist_ckpt/`` even with
the megatron-bridge backend (because megatron-bridge handles only base-model weights), sitting next to the
megatron-bridge-produced ``model/huggingface/`` tree.

Recommended Configurations
~~~~~~~~~~~~~~~~~~~~~~~~~~

- **Default / production**: keep ``use_mbridge=True`` and use ``save_contents=['model',
  'optimizer', 'extra']``. The ``model/huggingface/`` folder produced by megatron-bridge can be loaded
  directly by HuggingFace Transformers without any further conversion step.
- **HuggingFace-only export**: ``save_contents=['hf_model']`` (megatron-bridge required). Useful when
  you only need a deployable HF checkpoint and not a resumable training state.
- **Pure Megatron sharded model**: ``use_mbridge=False`` and ``use_dist_checkpointing=True``
  with ``save_contents=['model', 'optimizer', 'extra']``. The model goes into ``model/dist_ckpt/``.
  You can later run ``python -m verl.model_merger merge --backend megatron ...`` (see below) to
  produce an HF checkpoint.

- **Hybrid (resume + HF export)**: ``use_mbridge=True``, ``use_dist_checkpointing=True``, and
  e.g. ``save_contents=['model', 'hf_model', 'optimizer', 'extra']`` to write both
  ``model/dist_ckpt/`` and ``model/huggingface/`` in one step.

Convert FSDP and Megatron Checkpoints to HuggingFace Format Model
-----------------------------------------------------------------

We provide a tool to convert the FSDP and Megatron checkpoints to HuggingFace format model.
The tool is located in ``verl/model_merger``. For older versions of verl that don't include fsdp_config.json in checkpoints, you can use the legacy model merger located at ``verl/scripts/legacy_model_merger.py``.

The script supports two main sub-commands: `merge` (to convert and save checkpoints) and `test` (to validate merged checkpoints against a reference model).
The arguments for the `merge` sub-command are as follows:

.. code:: bash

    usage: python -m verl.model_merger merge [-h] --backend {fsdp,megatron,veomni} [--local_dir LOCAL_DIR] [--base_model_path BASE_MODEL_PATH] [--tie-word-embedding] [--is-value-model]
                         [--use_cpu_initialization] [--target_dir TARGET_DIR] [--hf_upload_path HF_UPLOAD_PATH] [--private]

    options:
    -h, --help            show this help message and exit
    --backend {fsdp,megatron,veomni}
                            The backend of the model
    --local_dir LOCAL_DIR
                            Path to the saved model checkpoints
    --base_model_path BASE_MODEL_PATH
                            Path to the HuggingFace model the training started from. Required by the veomni backend for models exported in their original quantized layout (DeepSeek-V4).
    --tie-word-embedding  Whether to tie word embedding weights (currently only Megatron supported)
    --is-value-model      Whether the model is a value model (currently only Megatron supported)
    --use_cpu_initialization
                            Whether to use CPU initialization for the model. This is useful for large models that cannot fit into GPU memory during initialization.
    --target_dir TARGET_DIR
                            Directory to save the merged huggingface model
    --hf_upload_path HF_UPLOAD_PATH
                            Hugging Face repository ID to upload the model
    --private             Whether to upload the model to a private Hugging Face repository

Example usage for merging Megatron checkpoints:

.. code:: bash

    python -m verl.model_merger merge \
        --backend megatron \
        --tie-word-embedding \
        --local_dir checkpoints/verl_megatron_gsm8k_examples/qwen2_5_0b5_megatron_saveload/global_step_1/actor \
        --target_dir /path/to/merged_hf_model

Example usage for distributed merging Megatron checkpoints:

.. code:: bash

    torchrun --nproc_per_node 1 --nnodes 8 --node_rank ${RANK} -m verl.model_merger merge \
        --backend megatron \
        --tie-word-embedding \
        --local_dir checkpoints/verl_megatron_gsm8k_examples/qwen2_5_0b5_megatron_saveload/global_step_1/actor \
        --target_dir /path/to/merged_hf_model

Example usage for merging FSDP checkpoints:

.. code:: bash

    python -m verl.model_merger merge \
        --backend fsdp \
        --local_dir checkpoints/verl_fsdp_gsm8k_examples/qwen2_5_0b5_fsdp_saveload/global_step_1/actor \
        --target_dir /path/to/merged_hf_model

Example usage for merging VeOmni checkpoints:

.. code:: bash

    python -m verl.model_merger merge \
        --backend veomni \
        --local_dir checkpoints/${project_name}/${exp_name}/global_step_10/actor \
        --base_model_path /path/to/DeepSeek-V4-Flash \
        --target_dir /path/to/merged_hf_model

The VeOmni merger also reassembles expert-parallel shards (routed experts on the ``ep_fsdp`` mesh). It streams
tensors from memory-mapped rank files, so host memory does not need to hold the whole checkpoint. Weights are
exported through the model's VeOmni checkpoint tensor converter, the same path used for rollout weight sync, so the
merger has no model-specific logic. Models whose converter defines ``export_weights`` (e.g. DeepSeek-V4, re-quantized
into the FP8/FP4 layout of ``--base_model_path``) require ``--base_model_path``; tensors that are not trained (e.g.
MTP layers) and non-weight files are then copied from the base model, so the output can be served by vLLM like the
base model. DeepSeek-V4 export needs an SM90+ GPU for quantization. Other models are exported in bf16 HuggingFace
format.


Megatron Merger details
-----------------------

The Megatron merger constructs models and maps their weights with Megatron-Bridge.
Install the same Megatron-Core/Bridge environment used for training, with a Bridge
version that supports the model architecture. This includes vision-language models
when their Bridge implementation supports full HF export.

The merger reads v2 checkpoints with weights in ``model/dist_ckpt`` and
HF artifacts in ``model/huggingface``. Both training checkpoints and
``scripts/converter_hf_to_mcore.py`` use this layout.
The merger accepts only the v2 layout. Before merging a legacy Megatron training
checkpoint, migrate it to v2:

.. code:: bash

    python scripts/migrate_megatron_checkpoint_layout.py \
        --checkpoint /path/to/legacy_checkpoint

All ranks participate in conversion. Under ``torchrun``, the merger uses pipeline
parallelism to distribute the model; MCore loads and reshards the stored weights.
Bridge owns the parameter mappings, including QKV, MoE experts, and vision weights.
The output includes HF weights, config, tokenizer, and processor artifacts.

To compare a checkpoint against a reference HF model, including sharded safetensors:

.. code:: bash

    torchrun --standalone --nproc_per_node=4 -m verl.model_merger test \
        --backend megatron \
        --local_dir /path/to/mcore_checkpoint \
        --test_hf_dir /path/to/reference_hf_model


HuggingFace to Megatron DistCheckpoint details
----------------------------------------------

The training engine can load HF weights directly through Megatron-Bridge, so an
initial conversion is optional. For workflows requiring MCore distributed weights,
the converter uses Bridge to load HF weights and saves a model-only checkpoint
in verl's v2 directory layout.

The converter accepts ``--tp_size``, ``--pp_size``, ``--ep_size``, and
``--etp_size``. All four default to 1. When PP is 1, it is inferred as
``WORLD_SIZE // lcm(TP, ETP * EP)``. The world size must be
divisible by both ``TP * PP`` and ``ETP * EP * PP``. Virtual pipeline
parallelism is disabled during conversion.

For example, to convert a MoE model with TP2/PP2/EP4/ETP1 on 8 GPUs:

.. code:: bash

    torchrun --standalone --nproc_per_node=8 scripts/converter_hf_to_mcore.py \
        --hf_model_path Qwen/Qwen3-30B-A3B \
        --output_path /path/to/mcore_checkpoint \
        --tp_size 2 --pp_size 2 --ep_size 4 --etp_size 1 \
        --test

The converter uses BF16. ``--test`` reloads the saved
checkpoint and compares every parameter with the HF-loaded Bridge model. It can
also verify an existing converter output without overwriting it.

The output contains ``model/dist_ckpt`` for the distributed model state and
``model/huggingface`` for config, tokenizer, and processor artifacts.
Pass the output root to the merger's ``--local_dir``. For engine initialization,
set ``actor_rollout_ref.actor.megatron.dist_checkpointing_path`` to
``/path/to/mcore_checkpoint/model/dist_ckpt`` and enable ``use_dist_checkpointing``.
The converted checkpoint contains model weights, not optimizer state or training progress.

Both tools retain ``--use_cpu_initialization`` to reduce model allocation on GPU;
a distributed accelerator environment is still required for conversion collectives.

.. note::

    Megatron provides multiple optimizer checkpoint formats controlled by:

    - ``dist_ckpt_optim_fully_reshardable``:

      - ``False`` (default, dp-reshardable):
        The optimizer checkpoint supports resuming with different data parallel sizes.
        This format is faster and has lower memory overhead during checkpoint saving.

      - ``True`` (fully-reshardable):
        The optimizer checkpoint supports resuming with arbitrary parallelism configurations.
        However, this format is slower and introduces additional memory overhead.

    - ``distrib_optim_fully_reshardable_mem_efficient``:

      When using fully-reshardable format, enabling this option switches communication
      from NCCL to Gloo to reduce CUDA memory usage, at the cost of performance.

.. warning::

    When ``dist_ckpt_optim_fully_reshardable=True``, saving optimizer checkpoints requires
    gathering optimizer states on data parallel rank 0. Although the final checkpoint is
    sharded, this introduces a temporary aggregation step during saving.

    This may increase CPU memory usage and lead to OOM issues for large models.
    We recommend using the default dp-reshardable format in most cases.
