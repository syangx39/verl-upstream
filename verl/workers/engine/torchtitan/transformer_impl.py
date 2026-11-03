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
The concrete Engine implementation using PyTorch TorchTitan parallelism (FSDP2 + TP + PP)
"""

import importlib
import json
import logging
import os
import re
import shutil
from contextlib import nullcontext
from typing import Any, Callable, Optional

import torch
import torch.distributed
from safetensors.torch import save_file as save_safetensors_file
from tensordict import TensorDict
from torch.distributed.tensor import DTensor
from torchtitan.components.checkpoint import CheckpointManager
from torchtitan.components.loss import CrossEntropyLoss
from torchtitan.components.lr_scheduler import LRSchedulersContainer
from torchtitan.components.optimizer import OptimizersContainer, ParamGroupConfig
from torchtitan.config import CompileConfig, DebugConfig, ParallelismConfig, TrainingConfig
from torchtitan.distributed import utils as dist_utils
from torchtitan.distributed.activation_checkpoint import FullAC, SelectiveAC
from torchtitan.distributed.context_parallel import prepare_context_parallel_input
from torchtitan.distributed.parallel_dims import ParallelDims
from torchtitan.train import Trainer

import verl.utils.torch_functional as verl_F
from verl.plugin.platform import get_platform
from verl.trainer.config import CheckpointConfig
from verl.utils import tensordict_utils as tu
from verl.utils.checkpoint.checkpoint_manager import BaseCheckpointManager
from verl.utils.dataset.dataset_utils import DatasetPadMode
from verl.utils.debug import log_gpu_memory_usage
from verl.utils.device import get_device_id, get_device_name
from verl.utils.fsdp_utils import (
    load_fsdp_model_to_gpu,
    load_fsdp_optimizer,
    offload_fsdp_model_to_cpu,
    offload_fsdp_optimizer,
)
from verl.utils.model import extract_multi_modal_inputs
from verl.utils.torch_functional import logprobs_from_logits
from verl.workers.config import HFModelConfig, TorchtitanEngineConfig, TorchtitanOptimizerConfig
from verl.workers.engine.torchtitan.tpu_utils import (
    align_micro_batch_shapes_across_ranks,
    apply_fp32_logits_tpu,
    apply_splash_attention_tpu,
    apply_tpu_precision_patches,
    bucket_length,
    compute_global_batch_num_tokens,
    configure_torch_compile_for_tpu,
    gather_cp_1d,
    get_tpu_seq_bucket_size,
    make_spmd_safe_parallelize_fn,
    monkey_patch_varlen_attention_tpu,
    pad_packed_inputs_for_tpu,
    safe_to_padded_tensor,
    synchronize_tpu_loss,
    tpu_eager_mode_context,
    unwrap_metadata,
    vocab_parallel_logprobs_from_logits,
)
from verl.workers.engine.torchtitan.utils import (
    NoOpDataLoader,
    configure_qwen3_moe_for_rl,
    derive_torchtitan_name_and_flavor,
    enable_fsdp_gradient_division,
    get_attention_masks,
    make_simple_fsdp_parallelize_fn,
)

from ..base import BaseEngine, BaseEngineCtx, EngineRegistry
from ..utils import detach_tree, enable_full_determinism, postprocess_batch_func, prepare_micro_batches


def _hf_entry_row_slots(name, spec, place, lidx, lval):
    """Dim-0 identity slot profile: slot ``e`` IS ``full[e]``, so a position's slot is one divmod away."""
    from ..spec import translate_flat_indices
    from ..utils import _prodshape

    slots = spec.hf_slots
    n_slots = len(slots)
    rows = int(spec.full_shape[0])
    assert n_slots == rows, (
        f"{name}: dim-0 identity slots need one slot per dim-0 row, got {n_slots} slots for {rows} rows; "
        "a converter that emits several HF tensors per row belongs on the to_hf_chunk path"
    )
    dtype_str = str(lval.dtype).replace("torch.", "")
    if lidx.numel() == 0:
        return slots, dtype_str, torch.zeros(n_slots, dtype=torch.int64), lidx.to(torch.int32), lval

    row_numel = max(_prodshape(spec.full_shape[1:]), 1)
    gidx = translate_flat_indices(lidx, place)
    edges = torch.arange(n_slots + 1, device=gidx.device, dtype=gidx.dtype) * row_numel
    # One D2H for the run lengths; the diff's nonzero already synced this stream.
    counts = torch.searchsorted(gidx, edges).diff().cpu()
    return slots, dtype_str, counts, (gidx % row_numel).to(torch.int32), lval


logger = logging.getLogger(__file__)
logger.setLevel(os.getenv("VERL_LOGGING_LEVEL", "WARN"))

device_name = get_device_name()

if device_name == "tpu":
    monkey_patch_varlen_attention_tpu()


class TorchTitanEngine(BaseEngine):
    """
    Concrete Engine implementation using PyTorch TorchTitan parallelism.

    Supports model sharding with FSDP2, tensor parallelism, activation/optimizer offloading,
    LoRA, and sequence parallelism following the TorchTitan design.
    """

    def __init__(
        self,
        model_config: HFModelConfig,
        engine_config: TorchtitanEngineConfig,
        optimizer_config: TorchtitanOptimizerConfig,
        checkpoint_config: CheckpointConfig,
    ):
        """
        Initialize the TorchTitanEngine.

        Sets up distributed device meshes for tensor and data parallelism, LoRA, and offload policies.

        Args:
            model_config: Configuration for HuggingFace model.
            engine_config: Configuration for FSDP/TorchTitan engine (uses FSDP2).
            optimizer_config: Configuration for optimizer.
            checkpoint_config: Configuration for checkpointing.
        """
        super().__init__()

        self.model_config = model_config
        self.engine_config = engine_config
        self.optimizer_config = optimizer_config
        self.checkpoint_config = checkpoint_config
        # Rotation bookkeeping for HuggingFace exports, built on the first save by the ranks that write them.
        self._hf_checkpoint_rotation: Optional[BaseCheckpointManager] = None
        self.engine_config.check_device_support(device_name)

        # Derive torchtitan model name and flavor from HF config
        torchtitan_name, torchtitan_flavor = derive_torchtitan_name_and_flavor(self.model_config.hf_config)

        # Get ModelSpec from model registry (use sdpa config when swapping in TPUSplashAttention with CP > 1
        # so Qwen3Model.Config.update_from_config does not reject VarlenAttention.Config and apply_compile
        # does not reject FlexAttention on backend='tpu').
        attn_backend = (
            "sdpa"
            if (
                device_name == "tpu"
                and self.engine_config.use_splash_attention
                and self.engine_config.context_parallel_size > 1
            )
            else self.engine_config.attn_type
        )
        model_module = importlib.import_module(f"torchtitan.models.{torchtitan_name}")
        model_spec = model_module.model_registry(torchtitan_flavor, attn_backend=attn_backend)
        if torchtitan_name == "qwen3":
            # MoE flavors only: route like the HF checkpoint the rollout serves (no expert bias, no aux loss)
            # and, on TPU, run the routed experts with the Pallas grouped matmul. Dense flavors are unchanged.
            model_spec.model = configure_qwen3_moe_for_rl(
                model_spec.model,
                use_pallas_grouped_mm=device_name == "tpu",
                expert_parallel_size=self.engine_config.expert_parallel_size,
                token_multiple=get_tpu_seq_bucket_size(),
            )
        self._use_simple_fsdp = self.engine_config.use_simple_fsdp
        if self._use_simple_fsdp:
            model_spec.parallelize_fn = make_simple_fsdp_parallelize_fn(
                model_spec.parallelize_fn, spmd_safe_blocks=device_name == "tpu"
            )
        elif device_name == "tpu" and self.engine_config.context_parallel_size > 1:
            model_spec.parallelize_fn = make_spmd_safe_parallelize_fn(model_spec.parallelize_fn)

        # Use foreach optimizer implementation on TPU.
        impl = "foreach" if get_platform().device_name == "tpu" else "fused"

        optimizer = OptimizersContainer.Config(
            implementation=impl,
            param_groups=[
                ParamGroupConfig(
                    pattern=r".*",
                    optimizer_name=self.optimizer_config.name,
                    optimizer_kwargs={
                        "lr": self.optimizer_config.lr,
                        "eps": self.optimizer_config.eps,
                        "betas": (self.optimizer_config.betas[0], self.optimizer_config.betas[1]),
                        "weight_decay": self.optimizer_config.weight_decay,
                    },
                )
            ],
        )

        total_steps = self.optimizer_config.total_training_steps
        lr_warmup_steps = self.optimizer_config.lr_warmup_steps
        if lr_warmup_steps is None or lr_warmup_steps <= 0:
            lr_warmup_steps = int(self.optimizer_config.lr_warmup_steps_ratio * total_steps)

        lr_scheduler = LRSchedulersContainer.Config(
            warmup_steps=lr_warmup_steps,
            decay_type=self.optimizer_config.decay_type,
            min_lr_factor=self.optimizer_config.min_lr_factor,
        )
        if device_name == "tpu" and self.engine_config.tensor_parallel_size > 1:
            # Tensor parallelism is not properly tested on TPU. With
            # tensor_parallel_degree > 1 torchtitan routes the model through
            # ``model.parallelize()``, which makes the logits a DTensor that has
            # to be reassembled with ``full_tensor()`` before the loss. That
            # backward path intermittently poisons the gradients with nan/inf
            # (observed as a single non-finite element in the tok_embeddings
            # shard). ``optimizer_step`` skips the update whenever grad_norm is
            # not finite, so the run still reports success while the policy
            # never trains. Use pure FSDP (tensor_parallel_size=1) instead.
            logger.warning(
                "tensor_parallel_size=%d is not supported on TPU: it produces non-finite "
                "gradients, which optimizer_step() silently skips, so the policy will not "
                "train. Set tensor_parallel_size=1 and use data_parallel_shard_size instead.",
                self.engine_config.tensor_parallel_size,
            )

        parallelism = ParallelismConfig(
            data_parallel_replicate_degree=self.engine_config.data_parallel_replicate_size,
            data_parallel_shard_degree=self.engine_config.data_parallel_shard_size,
            fsdp_reshard_after_forward=self.engine_config.reshard_after_forward,
            tensor_parallel_degree=self.engine_config.tensor_parallel_size,
            pipeline_parallel_degree=self.engine_config.pipeline_parallel_size,
            context_parallel_degree=self.engine_config.context_parallel_size,
            expert_parallel_degree=self.engine_config.expert_parallel_size,
            spmd_backend="default" if device_name == "tpu" else self.engine_config.spmd_backend,
        )
        checkpoint = CheckpointManager.Config(
            enable=True,
            interval=1,  # verl's trainer.save_freq controls when save_checkpoint is called.
            initial_load_in_hf=True,
            initial_load_model_only=True,
            initial_load_path=model_config.path,
        )
        # Set compile backend to 'tpu' when running on TPU.
        compile_config = CompileConfig(
            enable=self.engine_config.use_torch_compile,
            backend="tpu" if device_name == "tpu" else "inductor",
        )

        training_kwargs = {}
        if self.engine_config.mixed_precision_param is not None:
            training_kwargs["mixed_precision_param"] = self.engine_config.mixed_precision_param
        if total_steps > 0:
            training_kwargs["steps"] = total_steps
        if self.engine_config.max_seq_len is not None:
            training_kwargs["seq_len"] = self.engine_config.max_seq_len
        if (self.engine_config.offload_policy or self.engine_config.forward_only) and device_name != "tpu":
            training = TrainingConfig(enable_cpu_offload=True, **training_kwargs)
        else:
            training = TrainingConfig(**training_kwargs)

        # Activation checkpointing mode. Note: under spmd_backend="spmd_types" with
        # eager execution (use_torch_compile=False), selective/full AC recompute runs
        # on the autograd backward thread where the thread-local SPMD mesh is inactive,
        # so spmd.assert_type() raises "no current mesh". Set activation_checkpoint="none"
        # (or enable torch.compile, which recomputes in-graph) in that configuration.
        activation_checkpoint = {
            "selective": SelectiveAC.Config,
            "full": FullAC.Config,
            "none": lambda: None,
        }[self.engine_config.activation_checkpoint]()

        # Construct Torchtitan's Trainer.Config
        self.config = Trainer.Config(
            debug=DebugConfig(seed=self.engine_config.seed),
            model_spec=model_spec,
            hf_assets_path=self.model_config.path,
            optimizer=optimizer,
            lr_scheduler=lr_scheduler,
            parallelism=parallelism,
            checkpoint=checkpoint,
            compile=compile_config,
            training=training,
            activation_checkpoint=activation_checkpoint,
            # Use a no-op dataloader since verl has its own data loading
            dataloader=NoOpDataLoader.Config(),
            # Provide a concrete loss so Trainer.__init__ can build it;
            # verl uses its own loss function and ignores this one.
            loss=CrossEntropyLoss.Config(),
        )
        logger.warning(
            "TorchTitan grad clipping uses training.max_norm=%s; optim.clip_grad=%s is not passed to TorchTitan",
            self.config.training.max_norm,
            self.optimizer_config.clip_grad,
        )
        if device_name == "tpu" and self.engine_config.use_torch_compile:
            configure_torch_compile_for_tpu()
        self.trainer = Trainer(self.config)

        self._init_device_mesh()

        if device_name == "tpu":
            apply_tpu_precision_patches(self.trainer.model_parts)
            if self.engine_config.fp32_logits:
                apply_fp32_logits_tpu(self.trainer.model_parts)

        self._use_splash_attention = device_name == "tpu" and self.engine_config.use_splash_attention
        if self._use_splash_attention:
            apply_splash_attention_tpu(
                self.trainer.model_parts,
                cp_mesh=self.parallel_dims.get_optional_mesh("cp"),
            )
        elif self.engine_config.use_splash_attention and device_name != "tpu":
            logger.warning("use_splash_attention is only supported on TPU; ignoring it on %s", device_name)

        if device_name == "tpu" and self.engine_config.use_torch_compile:
            # nn.Module.compile() stores the compiled forward in `_compiled_call_impl`.
            n_compiled = sum(
                getattr(m, "_compiled_call_impl", None) is not None
                for part in self.trainer.model_parts
                for m in part.modules()
            )
            logger.warning(f"torch.compile(backend='tpu') enabled on {n_compiled} modules")

        if get_device_name() == "tpu" and torch.distributed.is_initialized():
            torch.distributed.barrier()

        # Re-enable FSDP's gradient division for verl's loss scaling.
        # TorchTitan disables gradient division by default (for global token normalization),
        # but verl's loss function multiplies by dp_size to compensate for gradient averaging.
        # SimpleFSDP has no divide factor (its backward reduce-scatter sums), so forward_backward_batch
        # scales the loss by 1 / dp_size before backward instead.
        use_loss_scale_for_dp = self._use_simple_fsdp or (
            device_name == "tpu" and self.engine_config.context_parallel_size > 1
        )
        self._simple_fsdp_loss_scale = 1.0 / self.get_data_parallel_size() if use_loss_scale_for_dp else None
        if self.engine_config.data_parallel_shard_size > 1 and not use_loss_scale_for_dp:
            dp_size = self.get_data_parallel_size()
            for model_part in self.trainer.model_parts:
                enable_fsdp_gradient_division(model_part, dp_size)

        if self.engine_config.full_determinism:
            enable_full_determinism(seed=self.engine_config.seed)

        # set FSDP offload params
        self._is_offload_param = self.engine_config.param_offload
        self._is_offload_optimizer = self.engine_config.optimizer_offload

        if self.engine_config.entropy_from_logits_with_chunking:
            entropy_from_logits = verl_F.entropy_from_logits_with_chunking
        else:
            entropy_from_logits = verl_F.entropy_from_logits

        if not self.engine_config.use_torch_compile:
            self.compute_entropy_from_logits = entropy_from_logits
        elif device_name == "tpu":
            # Inductor has no TPU codegen; shapes are bucketed, so compile them statically.
            self.compute_entropy_from_logits = torch.compile(entropy_from_logits, backend="tpu", dynamic=False)
        else:
            self.compute_entropy_from_logits = torch.compile(entropy_from_logits, dynamic=True)

    @property
    def is_param_offload_enabled(self) -> bool:
        return self._is_offload_param

    @property
    def is_optimizer_offload_enabled(self) -> bool:
        return self._is_offload_optimizer

    def is_mp_src_rank_with_outputs(self):
        """
        Whether the current rank is the first rank in model parallel group that contains model outputs
        """
        is_collect = True
        # TP: outputs are on TP rank 0
        if self.parallel_dims.tp > 1:
            tp_mesh = self.parallel_dims.get_optional_mesh("tp")
            is_collect = is_collect and (tp_mesh.get_local_rank() == 0)
        # PP: outputs are on the last PP rank
        if self.parallel_dims.pp > 1:
            pp_mesh = self.parallel_dims.get_optional_mesh("pp")
            is_collect = is_collect and (pp_mesh.get_local_rank() == self.parallel_dims.pp - 1)
        # CP: outputs are on CP rank 0
        if self.parallel_dims.cp > 1:
            cp_mesh = self.parallel_dims.get_optional_mesh("cp")
            is_collect = is_collect and (cp_mesh.get_local_rank() == 0)
        return is_collect

    def _drop_checkpoint_state_dict_cache(self):
        """Free torchtitan ``ModelWrapper.cached_state_dict`` after loading.

        The cache exists for async DCP staging (stable storage across saves). Parameter entries are views,
        but entries produced by module state_dict hooks are fresh allocations: with fused ``wqkv`` the split
        hook gathers full-size replicated ``wq/wk/wv`` per layer (fp32, ~3.4 GiB per chip for Qwen3-8B),
        which would otherwise stay resident for the whole run. ``ModelWrapper.state_dict()`` repopulates
        missing keys on the next save, so dropping the cache only costs a transient re-allocation then.
        """
        from torchtitan.components.checkpoint import MODEL

        wrapper = getattr(self.checkpointer, "states", {}).get(MODEL)
        if wrapper is not None and hasattr(wrapper, "cached_state_dict"):
            wrapper.cached_state_dict = {}

    def initialize(self):
        """
        Build the model, optimizer, and learning rate scheduler with TorchTitan parallelism.

        Applies device, dtype, and precision configurations, including mixed precision.
        Sets up checkpoint manager.
        """
        self.module = self.trainer.model_parts
        self.checkpointer = self.trainer.checkpointer
        # load initial HF weights
        self.checkpointer.load()
        self._drop_checkpoint_state_dict_cache()

        if not self.engine_config.forward_only:
            self.optimizer = self.trainer.optimizers
            self.lr_scheduler = self.trainer.lr_schedulers
        else:
            self.optimizer = None
            self.lr_scheduler = None
            self.trainer.optimizers = None
            self.trainer.lr_schedulers = None

        self.to(
            device="cpu",
            model=self._is_offload_param,
            optimizer=self._is_offload_optimizer,
            grad=self._is_offload_param,
        )

        log_gpu_memory_usage("After offload model/optimizer/grad during init", logger=logger)

    def _init_device_mesh(self):
        """Initialize the device mesh for TorchTitan style parallelism."""
        world_size = torch.distributed.get_world_size()
        self.parallel_dims = ParallelDims(
            dp_shard=self.engine_config.data_parallel_shard_size,
            dp_replicate=self.engine_config.data_parallel_replicate_size,
            cp=self.engine_config.context_parallel_size,
            tp=self.engine_config.tensor_parallel_size,
            pp=self.engine_config.pipeline_parallel_size,
            ep=self.engine_config.expert_parallel_size,
            world_size=world_size,
        )
        self.device_mesh = self.parallel_dims.build_mesh()

        # Mirror torchtitan's init_distributed (which verl bypasses): disable autograd
        # multithreading so backward-thread activation-checkpoint recompute can access the
        # thread-local SPMD mesh / process groups (e.g. current_spmd_mesh().get_group(...)).
        torch.autograd.set_multithreading_enabled(False)

    def train_mode(self, **kwargs):
        """Return a context manager for training mode."""
        return EngineTrainModeCtx(self, **kwargs)

    def eval_mode(self, **kwargs):
        """Return a context manager for evaluation mode."""
        return EngineEvalModeCtx(self, **kwargs)

    def get_data_parallel_rank(self):
        mesh = self._get_data_parallel_mesh()
        return 0 if mesh is None else mesh.get_local_rank()

    def get_data_parallel_size(self):
        return self.engine_config.data_parallel_shard_size * self.engine_config.data_parallel_replicate_size

    def get_data_parallel_group(self):
        mesh = self._get_data_parallel_mesh()
        if mesh is not None:
            return mesh.get_group()
        # If world_size == dp_size (e.g. single GPU, or all ranks are DP),
        # return WORLD so that collective ops in _postprocess_output
        # (allgather_dict_into_dict, all_reduce) still run and produce the
        # correct metric aggregation format.
        if torch.distributed.get_world_size() == self.get_data_parallel_size():
            return torch.distributed.group.WORLD
        return None

    def get_model_parallel_group(self):
        raise NotImplementedError

    def get_context_parallel_group(self):
        mesh = self.parallel_dims.get_optional_mesh("cp")
        return mesh.get_group() if mesh is not None else None

    def _get_data_parallel_mesh(self):
        """Get the data parallel mesh (dp_replicate * dp_shard, excluding cp/tp/pp)."""
        return self.parallel_dims.get_optional_mesh("batch")

    def forward_backward_batch(self, data: TensorDict, loss_function: Callable, forward_only=False):
        """Perform forward and optionally backward pass on a batch."""
        tu.assign_non_tensor(
            data,
            sp_size=self.engine_config.tensor_parallel_size * self.engine_config.context_parallel_size,
        )
        dp_group = self.get_data_parallel_group()
        is_tpu = get_device_name() == "tpu"

        if is_tpu:
            batch_num_tokens = compute_global_batch_num_tokens(
                data,
                dp_group,
                self.engine_config.tensor_parallel_size,
                self.engine_config.context_parallel_size,
            )
        else:
            batch_num_tokens = data["loss_mask"].sum().to(get_device_id())
            if dp_group is not None:
                torch.distributed.all_reduce(batch_num_tokens, op=torch.distributed.ReduceOp.SUM, group=dp_group)
            batch_num_tokens = batch_num_tokens if batch_num_tokens.device.type == "tpu" else batch_num_tokens.item()
        tu.assign_non_tensor(data, batch_num_tokens=batch_num_tokens)
        tu.assign_non_tensor(data, dp_size=self.get_data_parallel_size())

        micro_batches, indices = prepare_micro_batches(
            data=data,
            dp_group=self.get_data_parallel_group(),
            same_micro_num_in_dp=True,
        )
        if is_tpu and (self._use_simple_fsdp or self.engine_config.context_parallel_size > 1):
            # SimpleFSDP and Ulysses CP collectives run inside compiled blocks: every rank must run the same program.
            align_micro_batch_shapes_across_ranks(
                micro_batches,
                cp_size=self.engine_config.context_parallel_size,
            )

        output_lst = []

        ctx = torch.no_grad() if forward_only else nullcontext()

        # train_context activates the (thread-local) SPMD mesh required by spmd_types; it must
        # span backward too, since activation-checkpoint recompute re-runs the forward there.
        # record_function names each micro-batch so a forward-only stage (compute_log_prob /
        # compute_ref_log_prob) shows "micro_batch<i>" rows instead of a single anonymous forward.
        with tpu_eager_mode_context(self.engine_config.tpu_eager_mode) if is_tpu else nullcontext():
            for micro_batch_idx, micro_batch in enumerate(micro_batches):
                with (
                    self.trainer.train_context(),
                    ctx,
                    torch.profiler.record_function(f"micro_batch{micro_batch_idx}"),
                ):
                    loss, output = self.forward_step(
                        micro_batch, loss_function=loss_function, forward_only=forward_only
                    )
                    if not forward_only:
                        if self._simple_fsdp_loss_scale is not None:
                            # SimpleFSDP sums gradients across DP ranks; FSDP2 here averages them.
                            loss = loss * self._simple_fsdp_loss_scale
                        if is_tpu:
                            synchronize_tpu_loss(loss)
                        loss.backward()
                output_lst.append(output)

        return postprocess_batch_func(output_lst=output_lst, indices=indices, data=data)

    def model_forward_step(
        self,
        *,
        inputs: torch.Tensor,
        extra_inputs: dict[str, torch.Tensor] | None = None,
        extra_kwargs: dict[str, torch.Tensor] | None = None,
    ) -> torch.Tensor:
        """
        Perform a forward pass through the trainer model without backward.
        """
        model_parts = self.module
        parallel_dims = self.parallel_dims

        if parallel_dims.pp_enabled:
            raise NotImplementedError(
                "Pipeline parallelism is not yet supported in model_forward_step. "
                "This will be implemented in a follow-up PR."
            )
        else:
            # Non-PP forward. train_context (SPMD mesh) is set by the caller.
            assert len(model_parts) == 1
            pred = model_parts[0](inputs, **extra_inputs, **extra_kwargs)

        if isinstance(pred, DTensor):
            if get_device_name() == "tpu" and self.parallel_dims.tp_enabled:
                return pred
            pred = pred.full_tensor()
        return pred

    def forward_step(self, micro_batch: TensorDict, loss_function, forward_only):
        raise NotImplementedError("forward_step must be implemented in subclass")

    def optimizer_zero_grad(self):
        """Zero gradients."""
        self.optimizer.zero_grad()

    def optimizer_step(self):
        """Perform optimizer step with gradient clipping."""
        is_tpu = get_device_name() == "tpu"
        with tpu_eager_mode_context(self.engine_config.tpu_eager_mode) if is_tpu else nullcontext():
            # torch._foreach_norm (the `foreach=True` path) is unreliable on the TPU backend:
            # it returns inf even when every gradient is exactly zero. Since a non-finite
            # grad_norm makes this method skip the update entirely, that silently froze the
            # policy while the job still reported success. Use the per-tensor path there.
            grad_norm = dist_utils.clip_grad_norm_(
                [p for m in self.module for p in m.parameters()],
                self.config.training.max_norm,
                foreach=not is_tpu,
                pp_mesh=self.parallel_dims.get_optional_mesh("pp"),
                ep_enabled=self.parallel_dims.ep_enabled,
            )

            # If grad_norm is not finite the update is thrown away. This is silent by design,
            # so say it loudly: a run where this fires on every step reports success while the
            # policy never changes.
            if not torch.isfinite(grad_norm):
                logger.warning(f"grad_norm is not finite ({grad_norm}); skipping this optimizer step")
                self.optimizer.zero_grad()
            else:
                self.optimizer.step()
            return grad_norm.item()

    def lr_scheduler_step(self):
        """Advance learning rate scheduler."""
        self.lr_scheduler.step()
        lr = self.lr_scheduler.schedulers[0].get_last_lr()[0]
        return lr

    def to(self, device: str, model: bool = True, optimizer: bool = True, grad: bool = True):
        """Move model and/or optimizer to CPU or GPU."""
        super().to(device=device, model=model, optimizer=optimizer, grad=grad)

        if self.engine_config.forward_only:
            return

        device_name = get_device_name()
        assert device in (device_name, "cpu")
        if device == device_name:
            if model:
                for module in self.module:
                    load_fsdp_model_to_gpu(module)
            if optimizer and self.optimizer is not None:
                load_fsdp_optimizer(self.optimizer, device)
        elif device == "cpu":
            if model:
                for module in self.module:
                    offload_fsdp_model_to_cpu(module)
            if optimizer and self.optimizer is not None:
                offload_fsdp_optimizer(self.optimizer)
        else:
            raise ValueError(f"Invalid device type: {device}")

    def save_checkpoint(
        self,
        local_path: str,
        hdfs_path: Optional[str] = None,
        global_step: int = 0,
        max_ckpt_to_keep: Optional[int] = None,
        **kwargs,
    ) -> None:
        """Save TorchTitan distributed and/or HuggingFace safetensors checkpoint according to ``save_contents``.

        ``max_ckpt_to_keep`` also bounds the ``<local_path>/huggingface`` exports. TorchTitan's ``keep_latest_k`` only
        prunes its own DCP ``step-N`` folders, so every rank that writes an export rotates its own copies with the
        FSDP/Megatron checkpoint-manager policy (``BaseCheckpointManager``).
        """
        if self._is_offload_param:
            for module in self.module:
                load_fsdp_model_to_gpu(module)

        save_contents = (
            list(self.checkpoint_config.save_contents)
            if self.checkpoint_config is not None and self.checkpoint_config.save_contents is not None
            else ["model", "optimizer", "extra"]
        )

        # On host-local storage every host writes its own export, so rotation must run on each writer, not rank 0 only.
        hf_rotation = None
        if "hf_model" in save_contents and self._is_hf_checkpoint_writer(local_path):
            if self._hf_checkpoint_rotation is None:
                # Only the rotation bookkeeping of BaseCheckpointManager is used; it never touches model/optimizer.
                self._hf_checkpoint_rotation = BaseCheckpointManager(model=None, optimizer=None)
            hf_rotation = self._hf_checkpoint_rotation
            hf_rotation.ensure_checkpoint_capacity(max_ckpt_to_keep)

        if any(k in save_contents for k in ("model", "optimizer")):
            # Override TorchTitan's folder to use verl's path
            parent_dir = os.path.dirname(local_path)
            self.checkpointer.folder = parent_dir

            if max_ckpt_to_keep is not None:
                self.checkpointer.keep_latest_k = max_ckpt_to_keep

            self.checkpointer.save(curr_step=global_step)

        if "hf_model" in save_contents:
            self._save_hf_checkpoint(local_path)

        torch.distributed.barrier()
        if hf_rotation is not None:
            hf_rotation.register_checkpoint(os.path.join(local_path, "huggingface"), max_ckpt_to_keep)
        if self._is_offload_param:
            for module in self.module:
                offload_fsdp_model_to_cpu(module)

    @staticmethod
    def _is_hf_checkpoint_writer(local_path: str) -> bool:
        """Whether this rank writes (and rotates) the HuggingFace export under ``local_path``.

        Global rank 0 writes to shared storage; under host-local ``/tmp`` or ``/dev/shm`` the local rank 0 of every
        host writes its own copy.
        """
        rank = torch.distributed.get_rank() if torch.distributed.is_initialized() else 0
        ray_local_ws = int(os.environ.get("RAY_LOCAL_WORLD_SIZE", "0"))
        tpu_visible_chip = os.environ.get("TPU_VISIBLE_CHIPS", "")
        if tpu_visible_chip.isdigit():
            local_rank = int(tpu_visible_chip)
        elif ray_local_ws > 0:
            local_rank = rank % ray_local_ws
        else:
            local_rank = int(os.environ.get("LOCAL_RANK", "0"))
        return rank == 0 or (local_rank == 0 and local_path.startswith(("/dev/shm", "/tmp")))

    def _save_hf_checkpoint(self, local_path: str) -> None:
        """Export HuggingFace safetensors + config/tokenizer into ``<local_path>/huggingface``.

        Gathers 3D MoE expert stacks in bulk (e.g. 144 stacks on Qwen3-30B-A3B instead of 18,432 per-expert syncs),
        restricts CPU materialization to one writer per host, and flushes each completed safetensors shard
        immediately so peak host RAM stays bounded to ~1 shard rather than the full model.
        """
        should_write = self._is_hf_checkpoint_writer(local_path)

        params: dict[str, Any] = {}
        for module in self.module:
            params.update(module.state_dict())

        stacks: dict[str, list[tuple[str, tuple]]] = {}
        for name, param in params.items():
            slots = self._expert_stack_slots(name, param)
            if slots is not None:
                stacks[name] = slots
        expert_stacks = [(params[name], slots) for name, slots in stacks.items()]
        dense = self._to_hf_named_params({k: v for k, v in params.items() if k not in stacks})
        params.clear()

        hf_config = getattr(self.model_config, "hf_config", None)
        all_hf_keys = set(dense.keys()) | {hf_name for _stack, slots in expert_stacks for hf_name, _shape in slots}
        if getattr(hf_config, "tie_word_embeddings", False) and "model.embed_tokens.weight" in all_hf_keys:
            all_hf_keys.discard("lm_head.weight")

        hf_local_path = os.path.join(local_path, "huggingface")
        src_dir = getattr(self.model_config, "path", None)
        index_data: Optional[dict[str, Any]] = None
        new_weight_map: dict[str, str] = {}
        remaining_in_shard: dict[str, int] = {}
        pending_shards: dict[str, dict[str, torch.Tensor]] = {}
        single_state_dict: dict[str, torch.Tensor] = {}

        if should_write:
            os.makedirs(hf_local_path, exist_ok=True)
            if src_dir and os.path.isdir(src_dir):
                for fname in os.listdir(src_dir):
                    src_file = os.path.join(src_dir, fname)
                    if not os.path.isfile(src_file):
                        continue
                    if fname.endswith((".safetensors", ".bin", ".pt", ".pth", ".ckpt")) or fname in (
                        "model.safetensors.index.json",
                        "pytorch_model.bin.index.json",
                    ):
                        continue
                    shutil.copy2(src_file, os.path.join(hf_local_path, fname))

            if hf_config is not None and not os.path.isfile(os.path.join(hf_local_path, "config.json")):
                hf_config.save_pretrained(hf_local_path)
            tokenizer = getattr(self.model_config, "tokenizer", None)
            if tokenizer is not None and not os.path.isfile(os.path.join(hf_local_path, "tokenizer_config.json")):
                tokenizer.save_pretrained(hf_local_path)

            index_file = os.path.join(src_dir, "model.safetensors.index.json") if src_dir else ""
            if index_file and os.path.isfile(index_file):
                with open(index_file, encoding="utf-8") as f:
                    index_data = json.load(f)
                weight_map = index_data.get("weight_map", {})
                default_shard = next(iter(weight_map.values()), "model.safetensors")
                for k in sorted(all_hf_keys):
                    shard_name = weight_map.get(k, default_shard)
                    new_weight_map[k] = shard_name
                    remaining_in_shard[shard_name] = remaining_in_shard.get(shard_name, 0) + 1

        def _record_cpu_tensor(hf_name: str, cpu_tensor: torch.Tensor) -> None:
            if hf_name not in all_hf_keys:
                return
            if index_data is not None:
                shard_name = new_weight_map[hf_name]
                pending_shards.setdefault(shard_name, {})[hf_name] = cpu_tensor
                remaining_in_shard[shard_name] -= 1
                if remaining_in_shard[shard_name] == 0:
                    save_safetensors_file(
                        pending_shards.pop(shard_name),
                        os.path.join(hf_local_path, shard_name),
                        metadata={"format": "pt"},
                    )
            else:
                single_state_dict[hf_name] = cpu_tensor

        device = get_device_id()
        is_tpu = get_device_name() == "tpu"

        for name, param in dense.items():
            if isinstance(param, DTensor):
                full = param.to(device, dtype=torch.bfloat16, non_blocking=True).full_tensor()
            else:
                full = param.to(torch.bfloat16, non_blocking=True)
            if should_write and name in all_hf_keys:
                _record_cpu_tensor(name, full.detach().cpu().contiguous())
            elif is_tpu:
                get_platform().synchronize()
            del full
        dense.clear()

        for stack, slots in expert_stacks:
            full = stack.to(device, non_blocking=True)
            if isinstance(full, DTensor):
                full = full.full_tensor()
            full = full.to(torch.bfloat16, non_blocking=True)
            if should_write:
                full_cpu = full.detach().cpu().contiguous()
                for e, (hf_name, _shape) in enumerate(slots):
                    if hf_name in all_hf_keys:
                        _record_cpu_tensor(hf_name, full_cpu[e].clone())
                del full_cpu
            elif is_tpu:
                get_platform().synchronize()
            del full
        expert_stacks.clear()

        if should_write:
            if index_data is not None:
                for shard_name, shard_tensors in list(pending_shards.items()):
                    save_safetensors_file(
                        shard_tensors,
                        os.path.join(hf_local_path, shard_name),
                        metadata={"format": "pt"},
                    )
                pending_shards.clear()
                index_data["weight_map"] = new_weight_map
                with open(os.path.join(hf_local_path, "model.safetensors.index.json"), "w", encoding="utf-8") as f:
                    json.dump(index_data, f, indent=2)
            else:
                save_safetensors_file(
                    single_state_dict,
                    os.path.join(hf_local_path, "model.safetensors"),
                    metadata={"format": "pt"},
                )
                single_state_dict.clear()

            logger.warning("Saved HuggingFace checkpoint to %s", hf_local_path)

    def load_checkpoint(
        self, local_path: str, hdfs_path: Optional[str] = None, del_local_after_load: int = True, **kwargs
    ) -> None:
        """Load checkpoint."""
        if self._is_offload_param:
            for module in self.module:
                load_fsdp_model_to_gpu(module)

        # Override TorchTitan's folder to use verl's path
        parent_dir = os.path.dirname(local_path)
        self.checkpointer.folder = parent_dir

        # Extract step number from path (verl uses global_step_N format)
        match = re.search(r"global_step_(\d+)", local_path)
        if match:
            step = int(match.group(1))
            self.checkpointer.load(step=step)
        else:
            # Fallback to latest
            self.checkpointer.load(step=-1)

        torch.distributed.barrier()
        if self._is_offload_param:
            for module in self.module:
                offload_fsdp_model_to_cpu(module)

        if self._is_offload_optimizer:
            offload_fsdp_optimizer(self.optimizer)

    def _to_hf_named_params(self, params: dict[str, Any]) -> dict[str, Any]:
        """Re-key a torchtitan state dict to HuggingFace names, values untouched."""
        # Convert TorchTitan key names to HuggingFace key names (expected by vLLM)
        sd_adapter = self.checkpointer.sd_adapter
        if sd_adapter is not None:
            params = sd_adapter.to_hf(params)

        # When weight tying is enabled, the sd_adapter skips lm_head.weight during
        # to_hf() conversion (since it's the same tensor as embed_tokens.weight in
        # the torchtitan model). But vLLM needs lm_head.weight explicitly, so we
        # add it back as a reference to embed_tokens.weight.
        if "model.embed_tokens.weight" in params and "lm_head.weight" not in params:
            params["lm_head.weight"] = params["model.embed_tokens.weight"]
        return params

    def _expert_stack_slots(self, name: str, param: Any) -> Optional[list[tuple[str, tuple]]]:
        """If ``name`` is a fused expert stack, enumerate ALL its experts' HF tensors, else ``None``."""
        sd_adapter = self.checkpointer.sd_adapter
        from_hf_map = getattr(sd_adapter, "from_hf_map", None) if sd_adapter is not None else None
        if not from_hf_map or param.ndim < 2:
            return None
        abstract = re.sub(r"(\d+)", "{}", name, count=1)
        hf_template = next((hf for hf, titan in from_hf_map.items() if titan == abstract), None)
        if hf_template is None or hf_template.count("{}") != 2:
            return None
        layer_id = re.search(r"\d+", name).group(0)
        slot_shape = tuple(int(d) for d in param.shape[1:])
        return [(hf_template.format(layer_id, e), slot_shape) for e in range(int(param.shape[0]))]

    def _hf_delta_entry(self, name, spec, place, lidx, lval):
        """Build one parameter's final HF-coordinate delta entry: expert stack via slots, else identity."""
        from ..utils import _hf_entry_identity

        if spec.hf_slots is not None:
            return _hf_entry_row_slots(name, spec, place, lidx, lval)
        assert spec.to_hf_chunk is None, (
            f"{name}: the torchtitan engine has no opaque to-HF converters; "
            "a spec carrying one did not come from this engine"
        )
        return _hf_entry_identity(name, spec, place, lidx, lval)

    def get_per_tensor_param_delta_shard(self, **kwargs):
        """Yield FINAL HF-coordinate delta entries per parameter; needs a prior :meth:`prime_delta_snapshots`."""
        from ..utils import hf_delta_export

        self._delta_shard_snap = getattr(self, "_delta_shard_snap", {})
        gen, _ = self.get_per_tensor_param_shard()
        return hf_delta_export(gen, self._delta_shard_snap, self._hf_delta_entry), None

    def _assert_shard_export_supported(self) -> None:
        """Reject PP, the one layout whose local shard is not a block; every FSDP2 layout is one."""
        pd = self.parallel_dims
        if pd.pp_enabled:
            raise NotImplementedError(
                "the torchtitan sharded delta export does not support pipeline parallelism: "
                "each stage holds a disjoint slice of the model, so the export order is not "
                "identical across ranks the way the delta engine's lockstep gather requires "
                f"(pipeline_parallel_size={pd.pp})"
            )
        # TP, EP and HSDP replicate all stay blocks, so derive_dtensor_placement handles them.

    def get_per_tensor_param_shard(self, **kwargs):
        """Yield this rank's *local* shard ``(hf_name, local_flat_bf16, ShardSpec)`` instead of the full tensor."""
        self._assert_shard_export_supported()
        # TODO: skip the q/k/v all-gather. torchtitan builds Qwen3 with a fused ``wqkv`` (FusedQKVLinear,
        # Shard(0) over KV-group-interleaved rows), and ``state_dict()`` runs its ``_split_qkv_on_save`` hook,
        # which redistributes every layer's ``wqkv`` to Replicate() (an fp32 all-gather) before splitting it
        # into wq/wk/wv. So q/k/v come back fully replicated and every rank exports (and raiden binds) the full
        # tensors: ~1.8 GB bf16 per rank plus a ~3.6 GB fp32 transient at 8B, ~6.7 GB plus ~13.4 GB at 32B,
        # however many trainer ranks there are. Options:
        #   - build the model with fuse_qkv=False: works for any dp_shard, but torchtitan's model_registry
        #     does not expose the flag yet;
        #   - split the local ``wqkv`` shard without the hook: if n_kv_heads % dp_shard == 0 each rank holds
        #     whole KV groups, i.e. Shard(0) blocks of q_proj/k_proj/v_proj (8B on 8 ranks: one group of
        #     4 q + 1 k + 1 v heads). Qwen3-32B also has 8 KV heads, so this caps dp_shard at 8;
        #   - patch the hook to skip the gather in that case.
        # Check: at 8B, rank 0 should export q_proj as [512, 4096] instead of [4096, 4096].
        raw = {}
        for module in self.module:
            raw.update(module.state_dict())

        # Expert stacks go WHOLE with a slot table; to_hf would name only the local experts, breaking lockstep.
        stacks = {}
        for name, param in raw.items():
            slots = self._expert_stack_slots(name, param)
            if slots is not None:
                stacks[name] = slots
        params = self._to_hf_named_params({k: v for k, v in raw.items() if k not in stacks})
        device = get_device_id()  # local shards live on CPU under an offload policy

        from ..spec import ShardSpec

        def _shard(param):
            p = param.to(device, non_blocking=True)
            # The wire speaks bf16, but mixed precision keeps fp32 masters: cast before the diff sees them.
            if p.is_floating_point():
                p = p.to(torch.bfloat16, non_blocking=True)
            local = p.to_local() if isinstance(p, DTensor) else p
            return local.reshape(-1)

        def _gen():
            for name, param in params.items():
                yield name, _shard(param), ShardSpec.from_param(param)
            # Keyed by the torchtitan name: the entry is the stack, not any one HF tensor.
            for name, slots in stacks.items():
                spec = ShardSpec.from_param(raw[name])
                spec.hf_slots = slots
                yield name, _shard(raw[name]), spec

        return _gen(), None

    def get_per_tensor_param(self, **kwargs):
        for module in self.module:
            load_fsdp_model_to_gpu(module)

        params = {}
        for module in self.module:
            module_params = module.state_dict()
            params.update(module_params)

        if self._is_offload_param:
            for module in self.module:
                offload_fsdp_model_to_cpu(module)

        # Gather the stack before splitting it: to_hf splits first and drops every expert EFSDP holds elsewhere.
        stacks = {}
        for name, param in params.items():
            slots = self._expert_stack_slots(name, param)
            if slots is not None:
                stacks[name] = slots
        expert_stacks = [(params[name], slots) for name, slots in stacks.items()]
        dense = self._to_hf_named_params({k: v for k, v in params.items() if k not in stacks})
        params.clear()

        device = get_device_id()  # used when fsdp2 set cpu_offload_policy

        def _gen():
            # TODO: cast fp32 to bf16 to reduce weight sync overhead, need more fine-grained control, e.g MoE gate
            for name, param in dense.items():
                if isinstance(param, DTensor):
                    yield name, param.to(device, dtype=torch.bfloat16, non_blocking=True).full_tensor()
                else:
                    yield name, param.to(torch.bfloat16, non_blocking=True)
            # One stack at a time: the gathered (num_experts, ...) tensor is the peak allocation here.
            for stack, slots in expert_stacks:
                full = stack.to(device, non_blocking=True)
                if isinstance(full, DTensor):
                    full = full.full_tensor()
                full = full.to(torch.bfloat16, non_blocking=True)
                for e, (hf_name, _shape) in enumerate(slots):
                    yield hf_name, full[e].clone()
                del full

        # TODO: support Torchtitan PEFT
        return _gen(), None


class EngineEvalModeCtx(BaseEngineCtx):
    def __init__(self, engine: TorchTitanEngine, **kwargs):
        super().__init__(engine=engine, mode="eval", **kwargs)

    def __enter__(self):
        assert isinstance(self.engine, TorchTitanEngine)
        super().__enter__()
        for module in self.engine.module:
            module.eval()

    def __exit__(self, exc_type, exc_value, traceback):
        assert isinstance(self.engine, TorchTitanEngine)

        # Reshard every FSDP2 module: FSDPModule.reshard() is not recursive, so resharding only the root left
        # the per-layer modules gathered under reshard_after_forward="never". The isinstance check also makes
        # this a no-op under SimpleFSDP, whose modules are not FSDPModules (and have no reshard()).
        if self.engine.engine_config.data_parallel_shard_size > 1:
            from torch.distributed.fsdp import FSDPModule

            for module in self.engine.module:
                for submodule in module.modules():
                    if isinstance(submodule, FSDPModule):
                        submodule.reshard()

        super().__exit__(exc_type, exc_value, traceback)


class EngineTrainModeCtx(BaseEngineCtx):
    def __init__(self, engine: TorchTitanEngine, **kwargs):
        super().__init__(engine=engine, mode="train", **kwargs)

    def __enter__(self):
        assert isinstance(self.engine, TorchTitanEngine)
        super().__enter__()
        for module in self.engine.module:
            module.train()

    def __exit__(self, exc_type, exc_value, traceback):
        assert isinstance(self.engine, TorchTitanEngine)
        if self.zero_grad_on_exit or exc_type is not None:
            self.engine.optimizer_zero_grad()
        super().__exit__(exc_type, exc_value, traceback)


@EngineRegistry.register(model_type="language_model", backend=["torchtitan"], device=["cuda", "npu", "tpu"])
class TorchTitanEngineWithLMHead(TorchTitanEngine):
    """TorchTitan engine implementation for language models with LM head."""

    def prepare_model_inputs(self, micro_batch: TensorDict):
        use_remove_padding = tu.get_non_tensor_data(data=micro_batch, key="use_remove_padding", default=True)
        pad_mode = tu.get_non_tensor_data(data=micro_batch, key="pad_mode", default=DatasetPadMode.NO_PADDING)
        assert pad_mode == DatasetPadMode.NO_PADDING, f"pad_mode {pad_mode} not supported"

        multi_modal_inputs = extract_multi_modal_inputs(micro_batch.get("multi_modal_inputs", []))
        input_ids = micro_batch["input_ids"]
        position_ids = micro_batch["position_ids"]
        output_args = {}

        if use_remove_padding:
            if get_device_name() == "tpu":
                cp_mesh = self.parallel_dims.get_optional_mesh("cp")
                cp_size = cp_mesh.size() if cp_mesh is not None else 1
                cp_rank = cp_mesh.get_local_rank() if cp_mesh is not None else 0
                input_ids, position_ids, labels, attention_mask, orig_seq_len = pad_packed_inputs_for_tpu(
                    input_ids=input_ids,
                    position_ids=position_ids,
                    micro_batch=micro_batch,
                    device=get_device_id(),
                    build_attention_mask=not self._use_splash_attention,
                    cp_size=cp_size,
                    cp_rank=cp_rank,
                )
                output_args["orig_seq_len"] = orig_seq_len
            else:
                input_ids = input_ids.values().unsqueeze(0)
                if position_ids.dim() == 3:
                    position_ids = position_ids.values().unsqueeze(1)
                else:
                    position_ids = position_ids.values().unsqueeze(0)

                labels = torch.roll(input_ids, shifts=-1, dims=1)
                attn_type = self.engine_config.attn_type
                attention_mask = get_attention_masks(
                    input_batch=input_ids,
                    positions=position_ids,
                    attn_type=attn_type,
                )
        else:
            loss_mask = micro_batch["loss_mask"]
            pad_token_id = tu.get_non_tensor_data(data=micro_batch, key="pad_token_id", default=0)
            batch_size = micro_batch.batch_size[0]
            max_seq_len = int(max(input_ids.offsets().diff()))
            if get_device_name() == "tpu":
                max_seq_len = bucket_length(max_seq_len)

            to_padded_fn = safe_to_padded_tensor if get_device_name() == "tpu" else torch.nested.to_padded_tensor
            labels = torch.roll(input_ids.values(), shifts=-1, dims=0)
            input_ids = to_padded_fn(input_ids, padding=pad_token_id, output_size=(batch_size, max_seq_len))

            if position_ids.dim() == 3:
                position_ids = to_padded_fn(
                    position_ids, padding=0, output_size=(batch_size, 4, max_seq_len)
                ).transpose(0, 1)
            else:
                position_ids = to_padded_fn(position_ids, padding=0, output_size=(batch_size, max_seq_len))

            attention_mask_list = [torch.ones_like(t, dtype=torch.int32) for t in loss_mask]
            attention_mask = torch.nested.as_nested_tensor(attention_mask_list, layout=torch.jagged)
            attention_mask = to_padded_fn(attention_mask, padding=0, output_size=(batch_size, max_seq_len))

        extra_inputs = {
            "positions": position_ids,
        }
        # For arguments, like attention_masks, we have to put them in a separate
        # dict as extra_inputs are not forwarded to other stages in PP, but
        # extra_kwargs are.
        extra_kwargs: dict[str, Any] = {"attention_masks": attention_mask}
        if self.parallel_dims.cp_enabled and not (use_remove_padding and get_device_name() == "tpu"):
            extra_kwargs["positions"] = position_ids
            input_ids, labels, extra_kwargs = prepare_context_parallel_input(
                input_ids,
                labels,
                extra_kwargs,
                self.parallel_dims.get_mesh("cp"),
                self.trainer.device,
                self.trainer.config.parallelism.context_parallel_load_balancer,
            )
            extra_inputs["positions"] = extra_kwargs.pop("positions")

        # TODO(jessicazhong): multimodal is not yet supported for Torchtitan engine
        extra_inputs.update(multi_modal_inputs)
        output_args["labels"] = labels

        # Ensure all model inputs and kwargs are contiguous on TPU.
        if input_ids.device.type == "tpu":
            input_ids = input_ids.contiguous()
            extra_inputs = {k: v.contiguous() if isinstance(v, torch.Tensor) else v for k, v in extra_inputs.items()}
            extra_kwargs = {k: v.contiguous() if isinstance(v, torch.Tensor) else v for k, v in extra_kwargs.items()}

        return input_ids, extra_inputs, extra_kwargs, output_args

    def prepare_model_outputs(self, logits, output_args, micro_batch: TensorDict):
        use_remove_padding = tu.get_non_tensor_data(data=micro_batch, key="use_remove_padding", default=True)
        use_remove_padding = unwrap_metadata(use_remove_padding)

        pad_mode = tu.get_non_tensor_data(data=micro_batch, key="pad_mode", default=DatasetPadMode.NO_PADDING)
        pad_mode = unwrap_metadata(pad_mode)
        assert pad_mode == DatasetPadMode.NO_PADDING, f"pad_mode {pad_mode} not supported"

        temperature = micro_batch["temperature"]
        temperature = unwrap_metadata(temperature)

        calculate_entropy = tu.get_non_tensor_data(data=micro_batch, key="calculate_entropy", default=False)
        calculate_entropy = unwrap_metadata(calculate_entropy)

        labels = output_args["labels"]
        model_output = {}

        input_ids = micro_batch["input_ids"]
        cu_seqlens = input_ids.offsets()
        if isinstance(logits, DTensor) and not use_remove_padding:
            # The vocab-parallel path below only covers the packed (remove-padding) layout.
            logits = logits.full_tensor()
        if use_remove_padding:
            labels = labels.squeeze(0)
            if isinstance(logits, DTensor):
                tp_mesh = self.parallel_dims.get_optional_mesh("tp")
                tp_group = tp_mesh.get_group() if tp_mesh is not None else None
                log_probs = vocab_parallel_logprobs_from_logits(
                    logits=logits.squeeze(0),
                    labels=labels,
                    temperature=temperature,
                    tp_group=tp_group,
                )
                if calculate_entropy:
                    # Entropy needs the full vocab; the local shard alone gives a wrong value.
                    logits_rmpad = logits.full_tensor().squeeze(0) / temperature
            else:
                logits_rmpad = logits.squeeze(0)
                # PyTorch's autograd doesn't allow in-place modification of views when gradients need to flow back
                logits_rmpad = logits_rmpad / temperature

                inplace_backward = True
                if calculate_entropy:
                    inplace_backward = False
                log_probs = logprobs_from_logits(
                    logits=logits_rmpad,
                    labels=labels,
                    inplace_backward=inplace_backward,
                )

            if calculate_entropy:
                if not self.engine_config.entropy_checkpointing:
                    if self.engine_config.entropy_from_logits_with_chunking:
                        entropy_rmpad = self.compute_entropy_from_logits(
                            logits_rmpad,
                            chunk_size=self.engine_config.entropy_from_logits_chunk_size,
                        )  # ((total_nnz / sp) + pad)
                    else:
                        entropy_rmpad = self.compute_entropy_from_logits(logits_rmpad)
                else:
                    entropy_rmpad = torch.utils.checkpoint.checkpoint(self.compute_entropy_from_logits, logits_rmpad)

            padded_log_probs = log_probs.squeeze(0)
            if self.parallel_dims.cp_enabled:
                cp_group = self.get_context_parallel_group()
                padded_log_probs = gather_cp_1d(padded_log_probs, cp_group)
                if calculate_entropy:
                    entropy_rmpad = gather_cp_1d(entropy_rmpad, cp_group)
            orig_seq_len = output_args.get("orig_seq_len")
            if orig_seq_len is not None:
                cu_seqlens_cpu = cu_seqlens.detach().cpu()
                unpadded_log_probs = padded_log_probs.detach().cpu()[:orig_seq_len]
                log_probs = torch.nested.nested_tensor_from_jagged(unpadded_log_probs, cu_seqlens_cpu)
                log_probs._tpu_padded_values = padded_log_probs
                if calculate_entropy:
                    unpadded_entropy = entropy_rmpad.detach().cpu()[:orig_seq_len]
                    entropy = torch.nested.nested_tensor_from_jagged(unpadded_entropy, cu_seqlens_cpu)
                    entropy._tpu_padded_values = entropy_rmpad
            else:
                log_probs = torch.nested.nested_tensor_from_jagged(padded_log_probs, cu_seqlens)
                if calculate_entropy:
                    entropy = torch.nested.nested_tensor_from_jagged(entropy_rmpad, cu_seqlens)
        else:
            logits = logits / temperature
            if calculate_entropy:
                if not self.engine_config.entropy_checkpointing:
                    entropy = verl_F.entropy_from_logits(logits)
                else:
                    entropy = torch.utils.checkpoint.checkpoint(verl_F.entropy_from_logits, logits)

            seq_lengths = cu_seqlens.diff()
            starts = torch.zeros_like(seq_lengths, dtype=torch.int64)
            logits = torch.nested.narrow(logits, 1, starts, seq_lengths, layout=torch.jagged)
            logits_rmpad = torch.cat([t for t in logits.unbind()])
            log_probs = logprobs_from_logits(logits=logits_rmpad, labels=output_args["labels"])
            log_probs = torch.nested.nested_tensor_from_jagged(log_probs, cu_seqlens)
            if calculate_entropy:
                entropy = torch.nested.narrow(entropy, 1, starts, seq_lengths, layout=torch.jagged)
                entropy_rmpad = torch.cat([t for t in entropy.unbind()])
                entropy = torch.nested.nested_tensor_from_jagged(entropy_rmpad, cu_seqlens)

        model_output["log_probs"] = log_probs
        if calculate_entropy:
            model_output["entropy"] = entropy

        return model_output

    def forward_step(self, micro_batch: TensorDict, loss_function, forward_only):
        device_name = get_device_name()
        if device_name != "tpu":
            micro_batch = micro_batch.to(get_device_id())

        input_ids, extra_inputs, extra_kwargs, output_args = self.prepare_model_inputs(micro_batch=micro_batch)

        with torch.autocast(device_type=device_name, dtype=torch.bfloat16):
            logits = self.model_forward_step(inputs=input_ids, extra_inputs=extra_inputs, extra_kwargs=extra_kwargs)

            model_output = self.prepare_model_outputs(logits=logits, output_args=output_args, micro_batch=micro_batch)

            if loss_function is not None:
                loss, metrics = loss_function(
                    model_output=model_output, data=micro_batch, dp_group=self.get_data_parallel_group()
                )
            else:
                assert forward_only, "forward_only must be True when loss_function is None"
                loss = torch.tensor(1.0, device=device_name)
                metrics = {}

            for val in model_output.values():
                if hasattr(val, "_tpu_padded_values"):
                    delattr(val, "_tpu_padded_values")

            # Detach before this lands in forward_backward_batch's output_lst; see detach_tree.
            output = {
                "model_output": detach_tree(model_output),
                "loss": loss.detach().item(),
                "metrics": metrics,
            }

            return loss, output
