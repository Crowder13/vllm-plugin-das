# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Keep Mamba1 convolution weights in the causal-conv layout on HCU."""

from __future__ import annotations

import functools
from types import ModuleType

from ._common import (
    already_applied,
    load_exact_module,
    require_callable,
    require_class,
    require_exact_signature,
)

TARGET_MODULE = "vllm.model_executor.layers.mamba.mamba_mixer"
PATCH_ID = "worker.op_opt.mamba.mixer1_conv_layout"
TARGETS = (f"{TARGET_MODULE}.MambaMixer.__init__",)
_MARKER = "_vllm_hcu_mamba_mixer_applied"
_WRAPPER = "_vllm_hcu_mamba_mixer_wrapper"


def _nn_enabled() -> bool:
    from vllm_hcu.platforms import envs as henvs

    return bool(henvs.VLLM_USE_NN)


def _install_conv_weight_loader(layer) -> None:
    weight = layer.conv1d.weight
    # HCU's unquantized linear factory creates [kernel, channels].  Mamba1
    # never executes this object as a linear layer; both causal-conv kernels
    # consume [channels, kernel], so retain the checkpoint-facing layout.
    weight.data = weight.data.permute(2, 1, 0).contiguous()

    tp_rank = layer.conv1d.tp_rank

    def load_conv_weight(param, loaded_weight) -> None:
        if loaded_weight.shape == param.data.shape:
            local_weight = loaded_weight
        else:
            shard_size = param.data.shape[0]
            local_weight = loaded_weight.narrow(
                0,
                tp_rank * shard_size,
                shard_size,
            )
        if param.data.shape != local_weight.shape:
            raise AssertionError(
                "HCU Mamba1 conv weight shape mismatch: "
                f"parameter={tuple(param.data.shape)}, "
                f"loaded={tuple(local_weight.shape)}, tp_rank={tp_rank}"
            )
        param.data.copy_(local_weight)

    weight.weight_loader = load_conv_weight


def apply_to_module(module: ModuleType) -> bool:
    mixer = load_exact_module(TARGET_MODULE, module)
    cls = require_class(mixer, "MambaMixer", f"{TARGET_MODULE}.MambaMixer")
    wrapped = ((cls, "__init__", TARGETS[0], _WRAPPER),)
    if already_applied(mixer, _MARKER, wrapped):
        return False

    original_init = require_callable(cls, "__init__", TARGETS[0])
    require_exact_signature(
        original_init,
        TARGETS[0],
        positional=(
            "self",
            "hidden_size",
            "ssm_state_size",
            "conv_kernel_size",
            "intermediate_size",
            "time_step_rank",
            "use_conv_bias",
            "use_bias",
            "use_rms_norm",
            "rms_norm_has_weight",
            "rms_norm_eps",
            "activation",
            "is_lora_enabled",
            "model_config",
            "cache_config",
            "prefix",
        ),
        defaults={
            "rms_norm_has_weight": True,
            "rms_norm_eps": 1e-5,
            "activation": "silu",
            "is_lora_enabled": False,
            "model_config": None,
            "cache_config": None,
            "prefix": "",
        },
    )

    @functools.wraps(original_init)
    def hcu_init(self, *args, **kwargs):
        original_init(self, *args, **kwargs)
        if _nn_enabled():
            _install_conv_weight_loader(self)

    setattr(hcu_init, _WRAPPER, True)
    setattr(cls, "_vllm_hcu_original_init", original_init)
    setattr(cls, "__init__", hcu_init)
    setattr(mixer, _MARKER, True)
    return True


def apply(module: ModuleType | None = None) -> bool:
    return apply_to_module(load_exact_module(TARGET_MODULE, module))


__all__ = ["PATCH_ID", "TARGET_MODULE", "TARGETS", "apply", "apply_to_module"]
