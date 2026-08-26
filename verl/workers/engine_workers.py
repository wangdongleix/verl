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
import functools
import logging
import os
from contextlib import nullcontext
from copy import deepcopy
from functools import partial
from itertools import chain
from typing import Optional

import psutil
import torch
from codetiming import Timer
from omegaconf import DictConfig, open_dict
from tensordict import NonTensorData, TensorDict
from torch.distributed.device_mesh import init_device_mesh

from verl.checkpoint_engine import CheckpointEngineRegistry
from verl.single_controller.base import Worker
from verl.single_controller.base.decorator import Dispatch, make_nd_compute_dataproto_dispatch_fn, register
from verl.trainer.distillation import distillation_ppo_loss, is_distillation_enabled
from verl.utils import tensordict_utils as tu
from verl.utils.config import omega_conf_to_dataclass
from verl.utils.device import get_device_name, get_torch_device, set_expandable_segments
from verl.utils.distributed import initialize_global_process_group_ray, set_numa_affinity
from verl.utils.flops_counter import FlopsCounter
from verl.utils.import_utils import import_external_libs
from verl.utils.memory_utils import aggressive_empty_cache
from verl.utils.metric.utils import Metric
from verl.utils.profiler import DistProfiler, DistProfilerExtension, ProfilerConfig, log_gpu_memory_usage
from verl.utils.py_functional import append_to_dict
from verl.utils.tensordict_utils import maybe_fix_3d_position_ids
from verl.utils.torch_functional import allgather_dict_into_dict
from verl.workers.config import (
    ActorConfig,
    DistillationConfig,
    HFModelConfig,
    MtpConfig,
    RolloutConfig,
    TrainingWorkerConfig,
)
from verl.workers.rollout.base import BaseRollout, get_rollout_class
from verl.workers.rollout.r3_utils import is_kimi_full_r3_config
from verl.workers.utils.losses import ppo_loss

logger = logging.getLogger(__file__)
logger.setLevel(os.getenv("VERL_LOGGING_LEVEL", "WARN"))


def _restore_module_buffers_to_device(module) -> int:
    """Restore non-parameter buffers after an explicit FSDP2 CPU offload.

    ``FSDPEngine.to("cpu")`` uses ``module.cpu()`` for FSDP2 forward-only
    engines.  That also moves ordinary buffers (for example Kimi's vision
    RoPE ``time_weight``) to CPU, while the next FSDP pre-forward only
    re-materializes parameters.  Keeping those buffers on CPU makes the
    following forward mix CPU RoPE tensors with NPU activations.  Move only
    buffers back; parameter shards remain offloaded.
    """
    device = f"{get_device_name()}:{get_torch_device().current_device()}"
    moved = 0
    for buffer in module.buffers():
        if buffer is None or str(buffer.device) == device:
            continue
        buffer.data = buffer.data.to(device=device, non_blocking=True)
        moved += 1
    return moved


def _with_routing_replay_flag(enabled: bool):
    """Decorator to set 'enable_routing_replay' flag on the data TensorDict."""

    def decorator(func):
        @functools.wraps(func)
        def wrapper(self, data: TensorDict, *args, **kwargs):
            if enabled and getattr(self, "_rollout_r3_requested", False) and not self.enable_routing_replay:
                raise RuntimeError(
                    "routing replay was requested by rollout config but the actor "
                    "worker control plane disabled routing replay"
                )
            if self.enable_routing_replay:
                tu.assign_non_tensor_data(data, "enable_routing_replay", enabled)
                if enabled:
                    routed_experts = data.get("routed_experts", None)
                    routed_expert_weights = data.get(
                        "routed_expert_weights", None
                    )
                    if routed_experts is None:
                        raise RuntimeError(
                            "routing replay is active but the actor batch does "
                            "not contain routed_experts"
                        )
                    if (
                        getattr(self, "_kimi_full_r3_requested", False)
                        and routed_expert_weights is None
                    ):
                        raise RuntimeError(
                            "Kimi full R3 actor dispatch requires both "
                            "routed_experts and routed_expert_weights"
                        )
                    if getattr(self, "_kimi_full_r3_requested", False):
                        dispatch_counts = getattr(
                            self, "_kimi_r3_dispatch_counts", {}
                        )
                        invocation = dispatch_counts.get(func.__name__, 0) + 1
                        dispatch_counts[func.__name__] = invocation
                        self._kimi_r3_dispatch_counts = dispatch_counts
                        # A rank-0 heartbeat on every actor RPC makes a long
                        # run auditable step by step without producing 64
                        # duplicate lines per invocation.  The engine/model
                        # marker below this wrapper remains the stronger proof
                        # that Kimi actually returned after consuming R3.
                        if self.rank == 0:
                            marker = (
                                "Kimi full R3 actor DISPATCH ACTIVE: "
                                f"role={self.role} method={func.__name__} "
                                f"invocation={invocation} "
                                "ids_and_weights=True"
                            )
                            logger.warning(marker)
                            print(marker, flush=True)
            result = func(self, data, *args, **kwargs)
            if (
                enabled
                and getattr(self, "_kimi_full_r3_requested", False)
            ):
                invocation = getattr(self, "_kimi_r3_dispatch_counts", {}).get(
                    func.__name__, 0
                )
                if self.rank == 0:
                    if getattr(self, "_actor_strategy_name", "") in {
                        "fsdp",
                        "fsdp2",
                        "fsdp_turbo",
                    }:
                        # This wrapper can prove only that the routed batch was
                        # dispatched and that the nested actor RPC returned.  It
                        # cannot prove that prepare_model_inputs forwarded the
                        # routes or that KimiMoEGate consumed them.  Reserve the
                        # exact ``... R3 ACTIVE`` marker for the engine/model
                        # evidence points so operators cannot mistake an outer
                        # RPC success for successful replay.
                        marker = (
                            "FSDP Kimi full-model R3 WRAPPER RETURNED: "
                            f"role={self.role} method={func.__name__} "
                            f"invocation={invocation} model_returned=True"
                        )
                    else:
                        marker = (
                            "Kimi full R3 actor FORWARD COMPLETE: "
                            f"role={self.role} method={func.__name__} "
                            f"invocation={invocation} model_returned=True"
                        )
                    logger.warning(marker)
                    print(marker, flush=True)
            return result

        return wrapper

    return decorator


def _use_hccl_metric_collectives() -> bool:
    """Whether reporting-only metric reductions may use the default HCCL group.

    The loss reduction and metric ``all_gather_object`` below do not participate
    in forward/backward or weight synchronization.  On Ascend, however, AIV
    can leave these tiny collectives queued behind the main work and surface a
    timeout at a later ``update_weights`` synchronization point.  Keep exact
    cross-rank metric aggregation available as an explicit opt-in, while
    making the AIV path local and non-blocking by default.
    """

    setting = os.getenv("VERL_HCCL_METRIC_COLLECTIVES", "auto").strip().lower()
    if setting in {"1", "true", "yes", "on", "enable", "enabled"}:
        return True
    if setting in {"0", "false", "no", "off", "disable", "disabled"}:
        return False
    return os.getenv("HCCL_OP_EXPANSION_MODE", "").strip().upper() != "AIV"


class TrainingWorker(Worker, DistProfilerExtension):
    """
    TrainingWorker provides a Tinker-like API (https://thinkingmachines.ai/tinker/) as a RayWorkerGroup
    to a single controller. Currently, we only provide more coarse grained APIs,
    and do not provide exact APIs as Tinker does. But this can be added in the future.
    """

    def __init__(self, config: TrainingWorkerConfig):
        Worker.__init__(self)

        from verl.workers.engine import BaseEngine, EngineRegistry

        initialize_global_process_group_ray(timeout_second=None)

        set_numa_affinity()

        self.config = config
        self.model_config = self.config.model_config
        self.engine_config = self.config.engine_config
        self.optimizer_config = self.config.optimizer_config
        self.checkpoint_config = self.config.checkpoint_config
        self.device_name = get_device_name()
        self._use_hccl_metric_collectives = _use_hccl_metric_collectives()
        if not self._use_hccl_metric_collectives and self.rank == 0:
            logger.warning(
                "HCCL metric collectives are disabled for AIV; reporting uses local-rank metrics "
                "to keep non-training communication out of the critical path. Set "
                "VERL_HCCL_METRIC_COLLECTIVES=1 to opt back in."
            )

        if self.engine_config is None:
            assert self.optimizer_config is None
            if self.config.auto_select_engine_optim_fn is None:
                raise ValueError(
                    "engine_config is not provided and auto_select_engine_optim_fn is not set. "
                    "Cannot determine engine backend."
                )
            # Support automatically select engine backend given model config
            self.engine_config, self.optimizer_config = self.config.auto_select_engine_optim_fn(
                self.model_config, self.device_name
            )

        # we use the one defined in model
        # TODO: this is not elegant and should refactor later
        self.engine_config.use_remove_padding = self.model_config.get("use_remove_padding", False)
        self.engine_config.use_fused_kernels = self.model_config.get("use_fused_kernels", False)

        self.profiler_config = self.config.profiler_config
        if self.profiler_config is not None:
            self.profiler_tool_config = self.profiler_config.tool_config.get(self.profiler_config.tool, {})
        else:
            self.profiler_tool_config = None

        DistProfilerExtension.__init__(
            self,
            DistProfiler(
                rank=self.rank,
                config=self.profiler_config,
                tool_config=self.profiler_tool_config,
                # Embed the model role (e.g. language_model/value_model) in trace filenames
                # so standalone (e.g. SFT) traces are self-describing per process.
                save_file_prefix=getattr(self.config, "model_type", None),
            ),
        )

        self.model_config.model_type = self.config.model_type
        self.engine: BaseEngine = EngineRegistry.new(
            model_type=self.config.model_type,
            backend=self.engine_config.strategy,
            model_config=self.model_config,
            engine_config=self.engine_config,
            optimizer_config=self.optimizer_config,
            checkpoint_config=self.checkpoint_config,
        )

        # build dispatch info
        self._register_dispatch_collect_info(
            mesh_name="train",
            dp_rank=self.engine.get_data_parallel_rank(),
            is_collect=self.engine.is_mp_src_rank_with_outputs(),
        )

        if hasattr(self.model_config, "hf_config"):
            self.flops_counter = FlopsCounter(self.model_config.hf_config)
        else:
            self.flops_counter = None

        self.loss_fn = None

    @register(dispatch_mode=Dispatch.ONE_TO_ALL)
    def to(self, device, model=True, optimizer=True, grad=True):
        """Manual control of load/offload"""
        assert device in ["cpu", "device"]

        if device == "device":
            device = get_device_name()

        self.engine.to(device=device, model=model, optimizer=optimizer, grad=grad)

    @register(dispatch_mode=Dispatch.ONE_TO_ALL)
    def set_loss_fn(self, loss_fn):
        self.loss_fn = loss_fn

    @register(dispatch_mode=Dispatch.ONE_TO_ALL)
    def reset(self):
        """
        Reset the model engine to the initial state. If the engine is not initialized,
        we initialize it. Otherwise, reload ckpt and reset states
        """
        self.engine.initialize()

    def _postprocess_output(self, output, *, global_token_num, delta_time, forward_only, images_seqlens):
        """

        Args:
            output: a dictionary containing loss, model_outputs and metrics

        Returns:

        """

        metrics: dict = output.pop("metrics")
        # perform all gather in dp group to ensure that it's correct.
        # Here each metric in metrics can be a list (micro-batch metrics) or a singleton
        # we should always sum the loss of each micro-batch as we scale by global_bsz/global_token
        loss = torch.sum(torch.tensor(output.pop("loss"), device=self.device_name))
        dp_group = self.engine.get_data_parallel_group()
        # This is reporting-only; never make training depend on a small AIV
        # HCCL reduction that can be delayed until a later weight-sync fence.
        if dp_group is not None and self._use_hccl_metric_collectives:
            torch.distributed.all_reduce(loss, op=torch.distributed.ReduceOp.AVG, group=dp_group)
        loss = loss.item()

        # For grad_norm, we do not perform all reduce because it is already been done when clipping grad
        grad_norm = metrics.pop("grad_norm", None)
        if isinstance(grad_norm, torch.Tensor):
            grad_norm = grad_norm.detach().item()
        lr = metrics.pop("lr", None)

        # For other metrics, we perform all gather in dp group (only if DP > 1)
        if dp_group is not None and self._use_hccl_metric_collectives:
            final_metrics = allgather_dict_into_dict(data=metrics, group=dp_group)
        else:
            final_metrics = metrics
        final_metrics["loss"] = loss
        if grad_norm is not None:
            final_metrics["grad_norm"] = grad_norm
        if lr is not None:
            final_metrics["lr"] = lr

        # log memory
        final_metrics["perf/max_memory_allocated_gb"] = get_torch_device().max_memory_allocated() / (1024**3)
        final_metrics["perf/max_memory_reserved_gb"] = get_torch_device().max_memory_reserved() / (1024**3)
        final_metrics["perf/cpu_memory_used_gb"] = psutil.virtual_memory().used / (1024**3)

        # TODO: confirm the mtp loss IS same across dp
        for k, v in final_metrics.items():
            if k.startswith("mtp_losses"):
                flatten_v = [sublist[0] for sublist in v]  # sublist should be single element
                final_metrics[k] = sum(flatten_v) / len(flatten_v)
        # compute mfu
        if global_token_num is not None and self.flops_counter is not None:
            estimated_flops, promised_flops = self.flops_counter.estimate_flops(
                global_token_num, delta_time, images_seqlens=images_seqlens
            )
            final_metrics["mfu"] = estimated_flops / promised_flops / torch.distributed.get_world_size()
            if forward_only:
                final_metrics["mfu"] /= 3.0
        # model outputs
        model_output = output.pop("model_output", {})
        # We only return final_metrics
        final_output = tu.get_tensordict(tensor_dict=model_output, non_tensor_dict={"metrics": final_metrics})
        return final_output

    @register(dispatch_mode=make_nd_compute_dataproto_dispatch_fn(mesh_name="train"), blocking=False)
    def train_mini_batch(self, data: TensorDict) -> TensorDict:
        """Split a batch into N mini-batches run for multiple epochs

        Args:
            data:

        Returns:

        """
        maybe_fix_3d_position_ids(data)
        batch_size_per_dp = data.shape[0]
        disable_auto_offload = tu.pop(data, key="disable_auto_offload", default=False)
        mini_batch_size = tu.pop(data, key="mini_batch_size", default=None)
        num_mini_batch = tu.pop(data, key="num_mini_batch", default=None)
        epochs = tu.pop(data, key="epochs", default=1)
        seed = tu.pop(data, key="seed", default=42)
        dataloader_kwargs = tu.pop(data, key="dataloader_kwargs", default={})

        assert mini_batch_size is not None or num_mini_batch is not None

        if mini_batch_size is None:
            assert batch_size_per_dp % num_mini_batch == 0, f"Got {batch_size_per_dp=} and {num_mini_batch=}"
            mini_batch_size_per_gpu = batch_size_per_dp // num_mini_batch
        else:
            assert mini_batch_size % self.engine.get_data_parallel_size() == 0, (
                f"Got {mini_batch_size=} and {self.engine.get_data_parallel_size()=}"
            )
            mini_batch_size_per_gpu = mini_batch_size // self.engine.get_data_parallel_size()

        # make iterator
        dataloader = tu.make_iterator(
            data,
            mini_batch_size=mini_batch_size_per_gpu,
            epochs=epochs,
            seed=seed + self.engine.get_data_parallel_rank(),
            dataloader_kwargs=dataloader_kwargs,
        )

        with (
            self.engine.train_mode(disable_auto_offload=disable_auto_offload),
            Timer(name="train_batch", logger=None),
        ):
            # update
            output_lst = []
            total_num_iterations = data.shape[0] // mini_batch_size_per_gpu * epochs

            for batch_idx, mini_batch_td in enumerate(dataloader):
                maybe_fix_3d_position_ids(mini_batch_td)
                # add global token num
                if "input_ids" in mini_batch_td:
                    global_token_num = mini_batch_td["input_ids"].offsets().diff().tolist()  # (total_nnz,)
                    # allgather from dp rank
                    global_token_num_output = [None] * torch.distributed.get_world_size(
                        self.engine.get_data_parallel_group()
                    )
                    torch.distributed.all_gather_object(
                        global_token_num_output, global_token_num, self.engine.get_data_parallel_group()
                    )
                    global_token_num = [x for xs in global_token_num_output for x in xs]
                else:
                    global_token_num = None

                tu.assign_non_tensor(
                    mini_batch_td,
                    global_token_num=NonTensorData(global_token_num),
                    update_lr_scheduler=batch_idx == total_num_iterations - 1,
                    disable_auto_offload=True,
                )
                actor_output = self.train_batch(mini_batch_td)
                output_lst.append(actor_output)
                # Advance the profiler schedule once per mini-batch. No-op unless a
                # torch profiler schedule (wait/warmup/active/repeat) is active.
                self.profiler.step()

            if self.engine.is_mp_src_rank_with_outputs():
                actor_output = [tu.get(output, "metrics") for output in output_lst]
                metrics = {}
                for output in actor_output:
                    for key, val in output.items():
                        # flattn dp and micro batch
                        if isinstance(val, list):
                            # ``postprocess_batch_func`` already returns a flat
                            # list for per-micro-batch scalar metrics.  The
                            # cross-rank metric gather path returns a nested
                            # list, which is the only case that needs one-level
                            # flattening.  AIV intentionally skips that gather;
                            # treating its flat ``list[float]`` as nested causes
                            # ``chain.from_iterable(float)`` to fail at the
                            # first actor update.
                            if val and isinstance(val[0], Metric):
                                output[key] = Metric.aggregate_dp(val)
                            elif val and isinstance(val[0], (list, tuple)):
                                output[key] = list(chain.from_iterable(val))
                    append_to_dict(metrics, output)

                output = tu.get_tensordict(tensor_dict={}, non_tensor_dict={"metrics": metrics}).cpu()
            else:
                output = None
        return output

    @register(dispatch_mode=make_nd_compute_dataproto_dispatch_fn(mesh_name="train"), blocking=False)
    @DistProfiler.annotate(color="red", role="train_batch")
    def train_batch(self, data: TensorDict) -> TensorDict:
        assert self.loss_fn is not None, "loss function can't be None when calling train_batch"
        assert not self.engine_config.forward_only, "Can't run `train_batch` when forward_only is in the engine config."
        # global_token_num should be a list of number of tokens of each seq in this batch
        global_token_num = tu.get(data, key="global_token_num")
        disable_auto_offload = tu.get(data, key="disable_auto_offload", default=False)
        images_seqlens = tu.get(data, key="images_seqlens", default=None)

        # inject engineering parameters if not specified
        default_keys = dict(
            use_remove_padding=self.model_config.get("use_remove_padding", False),
            use_dynamic_bsz=self.engine_config.use_dynamic_bsz,
            max_token_len_per_gpu=self.engine_config.max_token_len_per_gpu,
            micro_batch_size_per_gpu=self.engine_config.micro_batch_size_per_gpu,
            use_fused_kernels=self.engine_config.use_fused_kernels,
        )

        for key, val in default_keys.items():
            if key not in data.keys():
                tu.assign_non_tensor(data, **{key: val})

        with (
            self.engine.train_mode(disable_auto_offload=disable_auto_offload),
            Timer(name="train_batch", logger=None) as timer,
        ):
            output = self.engine.train_batch(data, loss_function=self.loss_fn)
            # containing loss, model_output and metrics
            # for training, we only care about loss and metrics
        delta_time = timer.last

        update_lr_scheduler = tu.get(data, key="update_lr_scheduler", default=False)
        # update lr scheduler
        if update_lr_scheduler:
            lr = self.engine.lr_scheduler_step()
        else:
            lr = None

        if self.engine.is_mp_src_rank_with_outputs():
            # we don't need model_output in training. Maybe we change out mind later
            output.pop("model_output")
            if lr is not None:
                output["metrics"]["lr"] = lr
            final_output = self._postprocess_output(
                output,
                global_token_num=global_token_num,
                delta_time=delta_time,
                forward_only=False,
                images_seqlens=images_seqlens,
            ).cpu()
        else:
            final_output = None

        return final_output

    @register(dispatch_mode=make_nd_compute_dataproto_dispatch_fn(mesh_name="train"), blocking=False)
    def infer_batch(self, data: TensorDict) -> TensorDict:
        # add mfu calculator
        global_token_num = tu.get(data, key="global_token_num")
        compute_loss = tu.get(data, key="compute_loss", default=True)
        disable_auto_offload = tu.get(data, key="disable_auto_offload", default=False)
        no_lora_adapter = tu.pop(data, key="no_lora_adapter", default=False)
        images_seqlens = tu.get(data, key="images_seqlens", default=None)

        default_keys = dict(
            use_remove_padding=self.model_config.get("use_remove_padding", False),
            use_dynamic_bsz=self.engine_config.use_dynamic_bsz,
            max_token_len_per_gpu=self.engine_config.infer_max_token_len_per_gpu,
            micro_batch_size_per_gpu=self.engine_config.infer_micro_batch_size_per_gpu,
            use_fused_kernels=self.engine_config.use_fused_kernels,
        )

        for key, val in default_keys.items():
            if key not in data.keys():
                tu.assign_non_tensor(data, **{key: val})

        # for sft training, we need to compute loss in eval
        loss_function = self.loss_fn if compute_loss else None

        with (
            self.engine.eval_mode(disable_auto_offload=disable_auto_offload),
            Timer(name="eval_batch", logger=None) as timer,
        ):
            adapter_ctx = self.engine.disable_adapter() if no_lora_adapter else nullcontext()
            with adapter_ctx:
                output = self.engine.infer_batch(data, loss_function=loss_function)
        delta_time = timer.last

        if self.engine.is_mp_src_rank_with_outputs():
            final_output = self._postprocess_output(
                output,
                global_token_num=global_token_num,
                delta_time=delta_time,
                forward_only=True,
                images_seqlens=images_seqlens,
            ).cpu()
        else:
            final_output = None

        return final_output

    @register(dispatch_mode=Dispatch.ONE_TO_ALL)
    def save_checkpoint(self, local_path, hdfs_path=None, global_step=0, max_ckpt_to_keep=None):
        return self.engine.save_checkpoint(local_path, hdfs_path, global_step, max_ckpt_to_keep)

    @register(dispatch_mode=Dispatch.ONE_TO_ALL)
    def load_checkpoint(self, local_path, hdfs_path=None, del_local_after_load=False):
        return self.engine.load_checkpoint(local_path, hdfs_path, del_local_after_load)


class ActorRolloutRefWorker(Worker, DistProfilerExtension):
    """Hybrid worker that includes actor model, rollout and optional ref model.
    For standalone actor or rollout, use ActorWorker or BaseRollout respectively.

    NOTE: ActorRolloutRefWorker no longer support spmd mode and run native server mode.
    """

    actor_worker_cls = TrainingWorker
    ref_worker_cls = TrainingWorker

    def __init__(
        self, config: DictConfig, role: str, distillation_config: Optional[DistillationConfig] = None, **kwargs
    ):
        Worker.__init__(self)
        self.config = config
        self.distillation_config = distillation_config
        self.distillation_enabled = is_distillation_enabled(distillation_config)
        self.role = role
        self.actor: TrainingWorker | None = None
        self.ref: TrainingWorker | None = None
        self.rollout: BaseRollout = None
        assert self.role in ["actor", "rollout", "ref", "actor_rollout", "actor_rollout_ref"]
        self._is_actor = self.role in ["actor", "actor_rollout", "actor_rollout_ref"]
        self._is_rollout = self.role in ["rollout", "actor_rollout", "actor_rollout_ref"]
        self._is_ref = self.role in ["ref", "actor_rollout_ref"]

        if self._is_actor:
            omega_profiler_config = config.actor.get("profiler", {})
        elif self._is_rollout:
            # NOTE: In colocation mode, rollout config may not take effect (follow the actor config)
            # This is for extendability in AsyncRL cases
            omega_profiler_config = config.rollout.get("profiler", {})
        else:
            omega_profiler_config = config.ref.get("profiler", {})

        profiler_config = omega_conf_to_dataclass(omega_profiler_config, dataclass_type=ProfilerConfig)
        if omega_profiler_config.get("tool", None) in ["npu", "nsys", "torch", "torch_memory", "precision_debugger"]:
            tool_config = omega_conf_to_dataclass(
                omega_profiler_config.get("tool_config", {}).get(omega_profiler_config.get("tool"))
            )
        else:
            tool_config = None

        # Router replay is supported on the megatron engine and on the veomni
        # engine. Both expose `router_replay` on their per-strategy engine
        # config (the field lives on the shared `EngineConfig` base).
        actor_strategy = self.config.actor.strategy
        actor_strategy_name = str(
            getattr(actor_strategy, "value", actor_strategy)
        ).lower()
        self._actor_strategy_name = actor_strategy_name
        self._rollout_r3_requested = bool(
            self._is_actor
            and self.config.rollout.get(
                "enable_rollout_routing_replay", False
            )
        )
        if actor_strategy_name == "megatron":
            rr_mode = self.config.actor.megatron.router_replay.mode
        elif actor_strategy_name == "veomni":
            rr_mode = self.config.actor.veomni.router_replay.mode
        elif actor_strategy_name in ("fsdp", "fsdp2", "fsdp_turbo"):
            # R3 records expert ids in the rollout engine and replays them in
            # actor forwards.  FSDP has no strategy-local router_replay block,
            # so the rollout switch is its source of truth.  The existing
            # decorators below still set the flag to False for reference
            # forwards and True only for actor infer/update calls.
            rr_mode = (
                "R3"
                if self._rollout_r3_requested
                else "disabled"
            )
        else:
            rr_mode = "disabled"
        self.enable_routing_replay = rr_mode != "disabled"
        if self._rollout_r3_requested and not self.enable_routing_replay:
            raise RuntimeError(
                "rollout routing replay was requested but actor replay "
                f"resolved disabled: role={self.role!r}, "
                f"strategy={actor_strategy_name!r}, rr_mode={rr_mode!r}"
            )
        if self._rollout_r3_requested and self.rank == 0:
            logger.warning(
                "Routing replay worker CONTROL ACTIVE: role=%s strategy=%s "
                "requested=True enabled=%s rr_mode=%s",
                self.role,
                actor_strategy_name,
                self.enable_routing_replay,
                rr_mode,
            )

        # Keep the raw (un-dataclassed) role profiler config so the inner actor
        # TrainingWorker can build a matching DistProfiler in init_model. This lets
        # train_mini_batch drive the (process-global) torch profiler schedule via
        # profiler.step(), even though start/stop happen on this outer worker.
        # NOTE: we must rebuild via the hydra path (omega_conf_to_dataclass without
        # dataclass_type) so that tool_config entries are real dataclasses with
        # attribute access; the dataclass_type=ProfilerConfig variant above yields a
        # plain-dict tool_config that the inner torch profiler cannot consume.
        self._omega_profiler_config = omega_profiler_config

        DistProfilerExtension.__init__(
            self,
            DistProfiler(
                rank=self.rank,
                config=profiler_config,
                tool_config=tool_config,
                # Embed the worker role (actor/rollout/ref/...) in trace filenames so
                # per-process results are distinguishable across roles and ranks.
                save_file_prefix=self.role,
            ),
        )

    @register(dispatch_mode=Dispatch.ONE_TO_ALL)
    def set_loss_fn(self, loss_fn):
        self.actor.set_loss_fn(loss_fn=loss_fn)

    @register(dispatch_mode=Dispatch.ONE_TO_ALL)
    def to(self, device, model=True, optimizer=True, grad=True):
        """Manual control of load/offload"""
        self.actor.to(device=device, model=model, optimizer=optimizer, grad=grad)

    @register(dispatch_mode=Dispatch.ONE_TO_ALL)
    def init_model(self):
        model_config: HFModelConfig = omega_conf_to_dataclass(self.config.model)
        self._kimi_full_r3_requested = bool(
            self._rollout_r3_requested
            and is_kimi_full_r3_config(model_config.hf_config)
        )
        if self._kimi_full_r3_requested:
            rollout_name = str(self.config.rollout.get("name", "")).lower()
            if rollout_name != "vllm":
                raise RuntimeError(
                    "Kimi full R3 requires the vLLM rollout backend because "
                    "the SGLang/generic backend does not capture executed "
                    f"router weights; got rollout.name={rollout_name!r}"
                )
            if self.rank == 0:
                logger.warning(
                    "Kimi full R3 worker MODEL CONTROL ACTIVE: role=%s "
                    "rollout_backend=%s ids_and_weights_required=True",
                    self.role,
                    rollout_name,
                )

        # 1. build reference model
        if "ref" in self.role:
            # TODO: align ref config with actor config
            with open_dict(self.config.ref):
                self.config.ref.ppo_mini_batch_size = self.config.actor.ppo_mini_batch_size
                self.config.ref.ppo_micro_batch_size = self.config.ref.pop("log_prob_micro_batch_size", None)
                self.config.ref.ppo_micro_batch_size_per_gpu = self.config.ref.pop(
                    "log_prob_micro_batch_size_per_gpu", None
                )
                self.config.ref.use_dynamic_bsz = self.config.ref.pop("log_prob_use_dynamic_bsz", False)
                self.config.ref.ppo_max_token_len_per_gpu = self.config.ref.pop("log_prob_max_token_len_per_gpu", None)
            ref_config: ActorConfig = omega_conf_to_dataclass(self.config.ref)

            # The ref model does not need to enable MTP; force it to false.
            ref_config.model_config = deepcopy(model_config)
            ref_config.model_config.mtp = MtpConfig(enable=False)

            # Build the inner ref profiler config via the hydra path (same as the actor / SFT),
            # so its tool_config entries are real dataclass instances the torch profiler can read.
            # This puts the reference model's inner TrainingWorker on par with the actor's, so the
            # torch profiler (and the nsys/npu backends) support the reference model too, instead
            # of the ref silently running with a disabled no-op profiler.
            ref_omega_profiler_config = self.config.ref.get("profiler", {})
            ref_profiler_config = (
                omega_conf_to_dataclass(ref_omega_profiler_config) if ref_omega_profiler_config else None
            )

            # construct TrainingWorkerConfig
            ref_training_config = TrainingWorkerConfig(
                model_type=ref_config.model_config.get("model_type", "language_model"),
                model_config=ref_config.model_config,
                engine_config=ref_config.engine,
                optimizer_config=ref_config.optim,
                checkpoint_config=ref_config.checkpoint,
                profiler_config=ref_profiler_config,
            )

            # assign engine configs
            ref_training_config.engine_config.use_dynamic_bsz = self.config.ref.use_dynamic_bsz
            ref_training_config.engine_config.infer_max_token_len_per_gpu = self.config.ref.ppo_max_token_len_per_gpu
            ref_training_config.engine_config.infer_micro_batch_size_per_gpu = (
                self.config.ref.ppo_micro_batch_size_per_gpu
            )
            ref_training_config.engine_config.use_remove_padding = model_config.get("use_remove_padding", False)

            self.ref = self.ref_worker_cls(config=ref_training_config)
            self.ref.reset()
            self.set_dispatch_collect(mesh_name="ref", **self.ref.get_dispatch_collect())

        # 2. build actor model
        if "actor" in self.role:
            actor_config: ActorConfig = omega_conf_to_dataclass(self.config.actor)
            actor_config.model_config = model_config
            distillation_config: Optional[DistillationConfig] = (
                omega_conf_to_dataclass(self.distillation_config) if self.distillation_enabled else None
            )

            # Build the inner actor profiler config via the hydra path (same as SFT), so
            # its tool_config entries are real dataclass instances the torch profiler can
            # read. This gives the inner TrainingWorker a DistProfiler that shares the
            # process-global torch profiler, so per-mini-batch profiler.step() works.
            actor_profiler_config = (
                omega_conf_to_dataclass(self._omega_profiler_config) if self._omega_profiler_config else None
            )

            actor_training_config = TrainingWorkerConfig(
                model_type=actor_config.model_config.get("model_type", "language_model"),
                model_config=actor_config.model_config,
                engine_config=actor_config.engine,
                optimizer_config=actor_config.optim,
                checkpoint_config=actor_config.checkpoint,
                profiler_config=actor_profiler_config,
            )

            assert self.config.actor.use_dynamic_bsz == self.config.rollout.log_prob_use_dynamic_bsz

            # assign engine configs
            actor_training_config.engine_config.use_dynamic_bsz = self.config.actor.use_dynamic_bsz
            actor_training_config.engine_config.infer_max_token_len_per_gpu = (
                self.config.rollout.log_prob_max_token_len_per_gpu
            )
            actor_training_config.engine_config.infer_micro_batch_size_per_gpu = (
                self.config.rollout.log_prob_micro_batch_size_per_gpu
            )
            actor_training_config.engine_config.max_token_len_per_gpu = self.config.actor.ppo_max_token_len_per_gpu
            actor_training_config.engine_config.micro_batch_size_per_gpu = (
                self.config.actor.ppo_micro_batch_size_per_gpu
            )
            actor_training_config.engine_config.use_remove_padding = model_config.get("use_remove_padding", False)

            if self.config.actor.use_dynamic_bsz:
                assert self.config.rollout.log_prob_max_token_len_per_gpu is not None
                assert self.config.actor.ppo_max_token_len_per_gpu is not None
            else:
                assert self.config.rollout.log_prob_micro_batch_size_per_gpu is not None
                assert self.config.actor.ppo_micro_batch_size_per_gpu is not None
            if self.distillation_enabled:
                self.loss_fn = partial(
                    distillation_ppo_loss, config=actor_config, distillation_config=distillation_config
                )
            else:
                self.loss_fn = partial(ppo_loss, config=actor_config)
            self.actor = self.actor_worker_cls(config=actor_training_config)
            self.actor.reset()
            self.actor.set_loss_fn(self.loss_fn)
            self.set_dispatch_collect(mesh_name="actor", **self.actor.get_dispatch_collect())

        # FSDP-Turbo's CPUOffloadPolicy manages parameter residency during
        # forward/backward, but it intentionally clears ``_is_offload_param``.
        # Therefore initialize() leaves the initial local shards on NPU until
        # the first FSDP hook runs.  On colocated rollout workers this makes
        # vLLM's startup memory check see only ~24 GiB free per 64 GiB NPU,
        # even though the training model is not being used yet.  Explicitly
        # park the actor/ref models (and actor optimizer) on CPU before the
        # colocated vLLM engine is constructed.  The FSDP-Turbo offload policy
        # brings parameters back for the first forward as usual.
        if "rollout" in self.role and os.getenv("VERL_PRE_ROLLOUT_CPU_OFFLOAD", "1").strip().lower() in {
            "1",
            "true",
            "yes",
            "on",
        }:
            logger.warning("Pre-rollout CPU offload: moving actor/ref model state off NPU")

            if "ref" in self.role and self.ref is not None:
                self.ref.to(device="cpu", model=True, optimizer=False, grad=True)
            if "actor" in self.role and self.actor is not None:
                self.actor.to(device="cpu", model=True, optimizer=True, grad=True)
            aggressive_empty_cache(force_sync=True)

        # 3. build rollout engine
        if "rollout" in self.role:
            rollout_config: RolloutConfig = omega_conf_to_dataclass(self.config.rollout)

            # TODO: move rollout_device_mesh into ServerAdapter
            # 3.1 build rollout device mesh (sglang need only)
            infer_tp = rollout_config.tensor_model_parallel_size * rollout_config.data_parallel_size
            infer_pp = rollout_config.pipeline_model_parallel_size
            infer_world_size = infer_tp * infer_pp
            dp = self.world_size // infer_world_size
            assert self.world_size % infer_world_size == 0, (
                f"rollout world_size: {self.world_size} is not divisible by infer_world_size: {infer_world_size}"
            )
            rollout_device_mesh = init_device_mesh(
                get_device_name(), mesh_shape=(dp, infer_tp, infer_pp), mesh_dim_names=["dp", "infer_tp", "infer_pp"]
            )

            # 3.2 initialize rollout engine
            rollout_cls: type[BaseRollout] = get_rollout_class(rollout_config.name, rollout_config.mode)
            self.rollout = rollout_cls(
                config=rollout_config, model_config=model_config, device_mesh=rollout_device_mesh
            )

            # used for LoRA (base_sync_done is unused in merge-only mode but kept for Phase 2 adapter path)
            self.base_sync_done: bool = "dummy" not in self.config.rollout.load_format
            self.layered_summon = self.config.rollout.get("layered_summon", False)
            self.peft_merge: bool = model_config.lora.get("merge", False)

        # 4. build checkpoint engine
        if "actor" in self.role:
            checkpoint_engine_config = omega_conf_to_dataclass(self.config.rollout.checkpoint_engine)
            backend = checkpoint_engine_config.backend
            bucket_size = checkpoint_engine_config.update_weights_bucket_megabytes << 20
            engine_kwargs = checkpoint_engine_config.engine_kwargs.get(backend, {})
            # If custom_backend_module is set, import it so plugins can register
            # in CheckpointEngineRegistry before the backend is instantiated.
            import_external_libs(checkpoint_engine_config.custom_backend_module or None)
            self.checkpoint_engine = CheckpointEngineRegistry.new(
                backend, is_master=(torch.distributed.get_rank() == 0), bucket_size=bucket_size, **engine_kwargs
            )

        # Free cached GPU memory so colocated vLLM processes can see it via cudaMemGetInfo
        aggressive_empty_cache(force_sync=True)

    @register(dispatch_mode=make_nd_compute_dataproto_dispatch_fn(mesh_name="ref"))
    @DistProfiler.annotate(color="olive", role="ref_compute_log_prob")
    @_with_routing_replay_flag(enabled=False)
    def compute_ref_log_prob(self, data: TensorDict) -> TensorDict:
        output = self.ref.infer_batch(data=data)
        # The ref engine is forward-only and uses FSDP2 CPUOffloadPolicy.  That
        # policy releases full parameters after a forward, but keeps the root
        # local shards materialized on NPU.  Those shards are not needed during
        # the subsequent actor update and otherwise share the small HBM margin
        # with the actor's backward all-gathers.  Park the ref shard explicitly
        # after the CPU result has been materialized.  ``to("cpu")`` also moves
        # ordinary buffers; restore only those buffers so the next FSDP forward
        # does not mix CPU RoPE state with NPU activations.
        output = output.cpu() if output is not None else None
        if self.ref is not None and getattr(self.ref.engine.engine_config, "forward_only", False):
            self.ref.engine.to(device="cpu", model=True, optimizer=False, grad=False)
            moved_buffers = _restore_module_buffers_to_device(self.ref.engine.module)
            if moved_buffers:
                logger.debug("Restored %d ref buffers to NPU after CPU offload", moved_buffers)
            aggressive_empty_cache(force_sync=True)
        return output

    @register(dispatch_mode=make_nd_compute_dataproto_dispatch_fn(mesh_name="actor"))
    @DistProfiler.annotate(color="blue", role="actor_compute_log_prob")
    @_with_routing_replay_flag(enabled=True)
    def compute_log_prob(self, data: TensorDict) -> TensorDict:
        output = self.actor.infer_batch(data)

        return output.cpu() if output is not None else None

    @register(dispatch_mode=make_nd_compute_dataproto_dispatch_fn(mesh_name="actor"))
    @DistProfiler.annotate(color="red", role="actor_update")
    @_with_routing_replay_flag(enabled=True)
    def update_actor(self, data: TensorDict) -> TensorDict:
        output = self.actor.train_mini_batch(data=data)
        return output.cpu() if output is not None else None

    @register(dispatch_mode=Dispatch.ONE_TO_ALL)
    def load_checkpoint(self, local_path, hdfs_path=None, del_local_after_load=False):
        assert "actor" in self.role, "load_checkpoint only support actor role"
        self.actor.load_checkpoint(local_path, hdfs_path, del_local_after_load)

    @register(dispatch_mode=Dispatch.ONE_TO_ALL)
    def save_checkpoint(self, local_path, hdfs_path=None, global_step=0, max_ckpt_to_keep=None):
        assert "actor" in self.role, "save_checkpoint only support actor role"
        self.actor.save_checkpoint(local_path, hdfs_path, global_step, max_ckpt_to_keep)

    @register(dispatch_mode=Dispatch.ONE_TO_ALL, blocking=False)
    async def update_weights(self, global_steps: int = None, mode: str = "auto"):
        """Update weights from trainer to rollout.

        1. For sync training with colocated trainer and rollout, update rollout directly from model engine.
           - before update_weights: rollout should be in sleep mode.
           - after update_weights: rollout should be in wake_up mode.
        2. For async training with disaggregated trainer and rollout, send_weights only by checkpoint engine.

        LoRA handling: when model.lora.merge=True (peft_merge), LoRA is merged into
        base weights before sync. The engine returns full HF-keyed params with
        peft_config=None, so the rollout receives a standard weight update.

        Args:
            global_steps: Current global training step count, passed to rollout for logging/tracking.
            mode: Weight update strategy. Supported values:
                - ``"auto"``: Automatically resolve to the backend configured in
                  ``config.rollout.checkpoint_engine.backend`` (default).
                - ``"naive"``: Direct in-process weight sync between colocated trainer
                  and rollout. Used for synchronous training where both share the same
                  process. Rollout must be in sleep mode before this call.
                - Any other value: Delegates to
                  :meth:`checkpoint_engine.send_weights` for asynchronous weight
                  transfer via checkpoint engine, suitable for disaggregated
                  trainer/rollout deployments.
        """

        # Resolve mode: "auto" falls back to config, explicit values take precedence
        effective_mode = mode if mode != "auto" else self.config.rollout.checkpoint_engine.backend
        rollout_layout = {
            # RolloutConfig normalizes EP=1 to None, while the resharder uses
            # an explicit 1 so the single-EP case is handled identically.
            "expert_parallel_size": getattr(self.config.rollout, "expert_parallel_size", None) or 1,
            "tensor_parallel_size": getattr(self.config.rollout, "tensor_model_parallel_size", None) or 1,
            "data_parallel_size": getattr(self.config.rollout, "data_parallel_size", None) or 1,
            "pipeline_model_parallel_size": getattr(self.config.rollout, "pipeline_model_parallel_size", None) or 1,
        }

        # 0. send_weights only for async training with disaggregated trainer and rollout
        if effective_mode != "naive":
            if effective_mode == "delta_sharded":
                # the delta engine owns the sync state machine (seed vs steady,
                # snapshot prime), so it drives the training engine itself.
                metrics = await self.checkpoint_engine.send_weights(self.actor.engine, global_steps=global_steps)
                return metrics or {}
            per_tensor_param, _ = self.actor.engine.get_per_tensor_param(
                rollout_layout=rollout_layout
            )
            metrics = await self.checkpoint_engine.send_weights(per_tensor_param, global_steps=global_steps)
            return metrics or {}

        set_expandable_segments(False)
        aggressive_empty_cache(force_sync=True)
        log_gpu_memory_usage("Before resume weights", logger=logger)

        # 1. resume rollout memory (weights were released during sleep)
        if self.config.rollout.free_cache_engine:
            await self.rollout.resume(tags=["weights"])
        log_gpu_memory_usage("After resume weights", logger=logger)

        # 2. determine if we need a base weight sync (adapter path only)
        per_tensor_param, peft_config = self.actor.engine.get_per_tensor_param(
            layered_summon=self.layered_summon,
            base_sync_done=True,
            rollout_layout=rollout_layout,
        )

        do_lora_base_sync = False
        if not self.peft_merge and peft_config is not None:
            self.rollout.sleep_level = 1
            do_lora_base_sync = not self.base_sync_done

        # 3. sync weights: For SGLang, we need base first (when needed), then adapter/merged
        if do_lora_base_sync:
            per_tensor_param_base, peft_config = self.actor.engine.get_per_tensor_param(
                layered_summon=self.layered_summon,
                base_sync_done=False,
                rollout_layout=rollout_layout,
            )
            await self.rollout.update_weights(
                per_tensor_param_base, peft_config=peft_config, base_sync_done=False, global_steps=global_steps
            )

        await self.rollout.update_weights(
            per_tensor_param, peft_config=peft_config, base_sync_done=True, global_steps=global_steps
        )

        log_gpu_memory_usage("After update_weights", logger=logger)

        # 3. offload model to cpu
        if self.actor.engine.is_param_offload_enabled:
            self.actor.engine.to("cpu", model=True, optimizer=False, grad=False)
        aggressive_empty_cache(force_sync=True)

        # 4. resume kv_cache
        if self.config.rollout.free_cache_engine:
            await self.rollout.resume(tags=["kv_cache"])
        log_gpu_memory_usage("After resume kv_cache", logger=logger)

        self.base_sync_done = True
        set_expandable_segments(True)

    @register(dispatch_mode=Dispatch.DP_COMPUTE, blocking=False)
    def execute_checkpoint_engine(self, method: str, *args, **kwargs):
        """Execute checkpoint engine method.

        Args:
            method (str): Checkpoint engine method name.
            *args: Variable length argument list.
            **kwargs: Arbitrary keyword arguments.

        """
        return getattr(self.checkpoint_engine, method)(*args, **kwargs)
