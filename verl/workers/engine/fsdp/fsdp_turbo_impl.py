# Copyright (c) 2026 Huawei Technologies Co., Ltd. All Rights Reserved.
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

import logging
import math
import os
from contextlib import contextmanager

import torch

from verl.utils.fsdp_utils import fsdp2_load_full_state_dict
from verl.utils.device import get_device_id, get_device_name

from ..base import EngineRegistry
from .transformer_impl import FSDPEngineWithLMHead

logger = logging.getLogger(__file__)


@EngineRegistry.register(model_type="language_model", backend="fsdp_turbo", device=["cuda", "npu"])
class FSDPTurboEngineWithLMHead(FSDPEngineWithLMHead):
    def _streaming_local_load_enabled(self):
        mode = getattr(self.engine_config, "checkpoint_load_mode", "legacy_full_state")
        if mode not in {"legacy_full_state", "streaming_local"}:
            raise ValueError(
                f"Unsupported FSDP-Turbo checkpoint_load_mode={mode!r}; "
                "expected 'legacy_full_state' or 'streaming_local'."
            )
        if mode == "streaming_local":
            model_type = getattr(self.model_config.hf_config, "model_type", None)
            if model_type != "kimi_k3":
                raise ValueError(
                    "checkpoint_load_mode=streaming_local currently supports only "
                    f"Kimi-K3, got model_type={model_type!r}."
                )
            return True
        return False

    def _init_device_mesh(self):
        super()._init_device_mesh()
        self._init_parallel_state()

    def _init_parallel_state(self):
        from fsdp_turbo.distributed.parallel_state import get_parallel_state, init_parallel_state
        from fsdp_turbo.fsdp_turbo_config import FSDPTurboConfig, _dict_to_dataclass

        self.fsdp_turbo_config = _dict_to_dataclass(FSDPTurboConfig, self.engine_config.turbo_config)
        cpu_offload = bool(self.engine_config.offload_policy or self.engine_config.forward_only)
        fsdp_plan = self.fsdp_turbo_config.distributed.fsdp_plan
        fsdp_plan.cpu_offload = cpu_offload
        if cpu_offload and get_device_name() == "npu":
            # Avoid asynchronous pinned host copies on the NPU offload path.
            fsdp_plan.pin_memory = False
        reshard_after_forward = self.engine_config.reshard_after_forward
        if reshard_after_forward is None:
            reshard_after_forward = True
        fsdp_plan.reshard_after_forward = reshard_after_forward
        logger.info(
            "FSDP-Turbo parameter policy: cpu_offload=%s pin_memory=%s "
            "reshard_after_forward=%s forward_only=%s",
            cpu_offload,
            fsdp_plan.pin_memory,
            reshard_after_forward,
            self.engine_config.forward_only,
        )
        attn_implementation = getattr(self.fsdp_turbo_config.model, "attn_implementation", "eager")
        vision_attn_implementation = os.getenv(
            "VERL_FSDP_TURBO_VISION_ATTN_IMPLEMENTATION",
            attn_implementation,
        )
        for config in (
            self.model_config.hf_config,
            getattr(self.model_config.hf_config, "text_config", None),
        ):
            if config is not None:
                config._attn_implementation = attn_implementation
        vision_config = getattr(self.model_config.hf_config, "vision_config", None)
        if vision_config is not None:
            vision_config._attn_implementation = vision_attn_implementation
        init_parallel_state(self.fsdp_turbo_config)
        self._parallel_state = get_parallel_state()
        if self._is_ulysses_enabled():
            self._process_ulysses_config()

    def _build_module(self, load_pretrained=None, force_meta=False):
        # Do not let verl's Qwen VLM monkey patch slice the text model before
        # FSDP-Turbo's post-fusion model patch does the CP split.
        cp_size = self.ulysses_sequence_parallel_size
        self.ulysses_sequence_parallel_size = 1
        try:
            if self._streaming_local_load_enabled():
                load_pretrained = False
                force_meta = True
            return super()._build_module(load_pretrained=load_pretrained, force_meta=force_meta)
        finally:
            self.ulysses_sequence_parallel_size = cp_size

    def _build_fsdp_module(self, module):
        from fsdp_turbo.fsdp_turbo import FSDPTurbo

        if self._streaming_local_load_enabled():
            # Wrap the meta model first, then materialize only final local shards.
            module = FSDPTurbo(self.fsdp_turbo_config, module).model
            if self.engine_config.offload_policy or self.engine_config.forward_only:
                self._is_offload_param = False
                self._is_offload_optimizer = False
                self._uses_fsdp2_cpu_offload_policy = True

            from .streaming_loader import load_kimi_k3_checkpoint_to_local_shards

            materialize_device = (
                "cpu"
                if self.engine_config.offload_policy or self.engine_config.forward_only
                else get_device_id()
            )
            load_kimi_k3_checkpoint_to_local_shards(
                module,
                self.model_config.local_path,
                strict=getattr(self.engine_config, "checkpoint_load_strict", True),
                materialize_device=materialize_device,
            )
            if torch.distributed.is_available() and torch.distributed.is_initialized():
                torch.distributed.barrier()
            return module

        full_state = module.state_dict()
        module = FSDPTurbo(self.fsdp_turbo_config, module).model
        offload_policy = None
        if self.engine_config.offload_policy or self.engine_config.forward_only:
            self._is_offload_param = False
            self._is_offload_optimizer = False
            offload_policy = True
            self._uses_fsdp2_cpu_offload_policy = True
        fsdp2_load_full_state_dict(module, full_state, None, offload_policy)

        return module

    def _is_ulysses_enabled(self):
        return self._parallel_state.is_group_enable("ulysses")

    def _process_ulysses_config(self):
        if self.ulysses_sequence_parallel_size > 1:
            raise ValueError(
                "Do not enable both FSDP-Turbo CP and verl Ulysses SP. "
                "Use fsdp_kwargs.distributed.ulysses_parallel_size for Turbo CP "
                "and set ulysses_sequence_parallel_size=1."
            )

        self.model_config.hf_config._attn_implementation = "eager"
        self.ulysses_sequence_parallel_size = self._parallel_state.get_ulysses_group_size()
        self.ulysses_parallel_group = self._parallel_state.get_ulysses_group()
        self.use_ulysses_sp = True

    def get_data_parallel_rank(self):
        if not hasattr(self, "_parallel_state"):
            return super().get_data_parallel_rank()
        return self._parallel_state.get_data_rank()

    def get_data_parallel_size(self):
        if not hasattr(self, "_parallel_state"):
            return super().get_data_parallel_size()
        return self._parallel_state.get_data_group_size()

    def get_data_parallel_group(self):
        if not hasattr(self, "_parallel_state"):
            return super().get_data_parallel_group()
        return self._parallel_state.get_data_group()

    def is_mp_src_rank_with_outputs(self):
        if not hasattr(self, "_parallel_state"):
            return super().is_mp_src_rank_with_outputs()
        if self._is_ulysses_enabled():
            is_collect = self._parallel_state.get_ulysses_rank() == 0
        else:
            is_collect = True
        return is_collect

    @contextmanager
    def _gradient_sync_context(self, *, is_last_micro_batch: bool):
        # FSDP-Turbo owns gradient synchronization at its collective boundary.
        yield

    def optimizer_step(self):
        """
        Clip gradients, skip update if non-finite, and step optimizer.

        Returns:
            grad_norm (float): Norm of gradients before clipping.
        """
        assert self.optimizer_config.clip_grad is not None

        # getattr fallback: some subclasses (e.g. VeOmniEngine) bypass FSDPEngine.__init__.
        scaler = getattr(self, "scaler", None)

        # Unscale gradients before clip so the clip threshold is applied to true gradient
        # magnitudes, not scaled ones. scaler.step() will skip the update if any grad is inf/nan.
        if scaler is not None:
            scaler.unscale_(self.optimizer)

        from fsdp_turbo.training.clip_grads import clip_grad_norm

        grad_norm = clip_grad_norm(model=self.module, max_norm=self.optimizer_config.clip_grad)
        if not math.isfinite(grad_norm):
            rank = torch.distributed.get_rank() if torch.distributed.is_initialized() else 0
            marker = (
                "FSDP-Turbo NONFINITE GRADIENT: "
                f"rank={rank} grad_norm={grad_norm} optimizer_step=False"
            )
            logger.error(marker)
            self.optimizer.zero_grad()
            if os.getenv("VERL_FAIL_ON_NONFINITE_GRAD", "1").strip().lower() in {
                "1",
                "true",
                "yes",
                "on",
            }:
                raise FloatingPointError(marker)
            if scaler is not None:
                scaler.update()
        elif scaler is not None:
            # scaler handles inf/nan skipping internally via _check_inf_per_device.
            scaler.step(self.optimizer)
            scaler.update()
        else:
            self.optimizer.step()

        if self._qat_enabled:
            from verl.utils.qat.core import invalidate_all_scales

            invalidate_all_scales(self.module)

        return grad_norm
