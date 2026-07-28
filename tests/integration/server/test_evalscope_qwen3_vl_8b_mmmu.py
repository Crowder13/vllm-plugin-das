# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Qwen3-VL-8B OpenAI server + EvalScope MMMU accuracy test."""

from __future__ import annotations

from pathlib import Path

import pytest

from tests.integration.server.evalscope_server import (
    load_config,
    run_evalscope_server_test,
)


ROOT = Path(__file__).resolve().parents[3]
DEFAULT_CONFIG = ROOT / "tests/models/qwen3_vl_8b_mmmu_evalscope.yaml"


pytestmark = [
    pytest.mark.hcu,
    pytest.mark.model,
    pytest.mark.hcu_count(1),
    pytest.mark.slow,
    pytest.mark.nightly,
    pytest.mark.external_service("evalscope"),
]


def test_qwen3_vl_8b_mmmu_evalscope_server() -> None:
    config = load_config(
        DEFAULT_CONFIG,
        "VLLM_HCU_QWEN3_VL_8B_MMMU_CONFIG",
    )
    run_evalscope_server_test(
        config,
        model_env="VLLM_HCU_QWEN3_VL_8B_MODEL",
        model_label="Qwen3-VL-8B-Instruct",
        required_hcu_count=1,
    )
