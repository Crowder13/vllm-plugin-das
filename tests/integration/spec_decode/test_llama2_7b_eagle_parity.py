# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Real EAGLE speculative-decoding smoke parity."""

from __future__ import annotations

import pytest

from tests.fixtures.resources import TestResources as HcuTestResources
from tests.integration.model_runtime import (
    require_model_architecture,
    require_model_runtime,
    run_vllm_case,
)


LLAMA2_7B = "vllm-optest-models/TheBloke/Llama-2-7B-fp16"
EAGLE_LLAMA2_7B = "vllm-optest-models/yuhuili/EAGLE-llama2-chat-7B"
SUPPORTED_EAGLE_DRAFT_ARCHITECTURES = {
    "EagleLlamaForCausalLM",
    "LlamaForCausalLM",
}

pytestmark = [
    pytest.mark.hcu,
    pytest.mark.model,
    pytest.mark.hcu_count(1),
    pytest.mark.slow,
]


def test_llama2_7b_eagle_spec_decode_token_parity(
    hcu_test_resources: HcuTestResources,
) -> None:
    model_path = require_model_runtime(
        hcu_test_resources,
        env_name="VLLM_HCU_SPEC_TARGET_MODEL",
        relative_path=LLAMA2_7B,
        label="Llama-2-7B-fp16 spec target",
    )
    draft_path = require_model_runtime(
        hcu_test_resources,
        env_name="VLLM_HCU_SPEC_DRAFT_MODEL",
        relative_path=EAGLE_LLAMA2_7B,
        label="EAGLE-llama2-chat-7B draft",
    )
    require_model_architecture(
        hcu_test_resources,
        draft_path,
        label="EAGLE-llama2-chat-7B draft",
        supported_architectures=SUPPORTED_EAGLE_DRAFT_ARCHITECTURES,
    )

    result = run_vllm_case(
        "spec-decode-parity",
        model_path,
        timeout_s=2400,
        extra_args=["--draft-model", str(draft_path)],
    )

    baseline_tokens = [item["token_ids"] for item in result["baseline"]]
    speculative_tokens = [item["token_ids"] for item in result["speculative"]]
    assert speculative_tokens == baseline_tokens
    assert all(tokens for tokens in speculative_tokens)
