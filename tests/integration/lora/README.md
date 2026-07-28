# LoRA integration

Real adapter loading and switching tests live here.

The initial coverage uses `qwen3/Qwen3-4B` plus two local adapters:

- `lora/TanXS/Qwen3-4B-LoRA-ZH-WebNovelty-v0.0`
- `lora/nissenj/Qwen3-4B-lora-v2`

Override paths with:

- `VLLM_HCU_LORA_BASE_MODEL`
- `VLLM_HCU_QWEN3_4B_LORA_A`
- `VLLM_HCU_QWEN3_4B_LORA_B`

Run only this coverage with:

```bash
python tools/run_patch_tests.py --suite model -k qwen3_4b_lora
```
