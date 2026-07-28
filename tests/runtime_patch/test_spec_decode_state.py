# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Model-free Spec Decode and multi-layer MTP state contracts."""

from __future__ import annotations

from types import SimpleNamespace

import pytest
import torch

from vllm_hcu.v1.spec_decode import proposer_runtime


def _config(**hcu: object) -> SimpleNamespace:
    return SimpleNamespace(
        additional_config={"hcu": hcu},
        parallel_config=SimpleNamespace(tensor_parallel_size=4),
    )


@pytest.mark.parametrize(
    ("enable_sp", "enable_custom_sp", "tp_size", "tokens", "expected"),
    [
        (False, False, 4, 5, 5),
        (True, False, 4, 5, 8),
        (False, True, 4, 5, 8),
        (True, True, 1, 5, 5),
        (True, True, 4, 8, 8),
    ],
)
def test_spec_decode_sequence_parallel_padding_policy(
    enable_sp: bool,
    enable_custom_sp: bool,
    tp_size: int,
    tokens: int,
    expected: int,
) -> None:
    proposer = SimpleNamespace(
        compilation_config=SimpleNamespace(
            pass_config=SimpleNamespace(enable_sp=enable_sp),
        ),
        vllm_config=_config(enable_custom_sp=enable_custom_sp),
    )
    proposer.vllm_config.parallel_config.tensor_parallel_size = tp_size

    assert proposer_runtime.pad_for_sequence_parallelism(proposer, tokens) == expected


def test_spec_decode_lightly_cp_requires_runner_threshold() -> None:
    proposer = SimpleNamespace(enable_lightly_cp=True, runner=SimpleNamespace())

    with pytest.raises(RuntimeError, match="runner.lightly_cp_threshold"):
        proposer_runtime._lightly_cp_active(proposer, 64)


def test_spec_decode_lightly_cp_threshold_is_strictly_greater_than() -> None:
    proposer = SimpleNamespace(
        enable_lightly_cp=True,
        runner=SimpleNamespace(lightly_cp_threshold=32),
    )

    assert proposer_runtime._lightly_cp_active(proposer, 32) is False
    assert proposer_runtime._lightly_cp_active(proposer, 33) is True


def test_multi_layer_mtp_preserves_independently_trained_heads_only() -> None:
    target_weight = torch.tensor([[1.0, 2.0]])
    own_weight = torch.tensor([[3.0, 4.0]])
    duplicate_weight = target_weight.clone()
    nan_weight = torch.tensor([[float("nan"), 0.0]])

    target_head = SimpleNamespace(weight=target_weight)
    own_head = SimpleNamespace(weight=own_weight)
    duplicate_head = SimpleNamespace(weight=duplicate_weight)
    nan_head = SimpleNamespace(weight=nan_weight)
    layers = [
        SimpleNamespace(shared_head=SimpleNamespace(head=own_head)),
        SimpleNamespace(shared_head=SimpleNamespace(head=duplicate_head)),
        SimpleNamespace(shared_head=SimpleNamespace(head=nan_head)),
    ]
    proposer = SimpleNamespace(
        model=SimpleNamespace(model=SimpleNamespace(layers=layers)),
    )
    target_language_model = SimpleNamespace(lm_head=target_head)

    def official_share(self, target):
        for layer in self.model.model.layers:
            layer.shared_head.head = target.lm_head
        return "shared"

    result = proposer_runtime.preserve_multi_layer_mtp_heads(
        proposer,
        target_language_model,
        official_share,
    )

    assert result == "shared"
    assert layers[0].shared_head.head is own_head
    assert layers[1].shared_head.head is target_head
    assert layers[2].shared_head.head is target_head
