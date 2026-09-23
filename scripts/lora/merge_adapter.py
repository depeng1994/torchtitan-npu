# Copyright (c) 2026 Huawei Technologies Co., Ltd. All rights reserved.
#
# This source code is licensed under the BSD-style license found in the
# LICENSE file in the root directory of this source tree.


"""Merge LoRA into a floating-point checkpoint without changing its format."""

import argparse
import json
import math
import os
import shutil

from safetensors import safe_open
from safetensors.torch import load_file, save_file

from torchtitan_npu.models.deepseek_v4.lora import build_lora_merge_plan, merge_lora_weight


def _load_adapter_config(adapter_dir: str) -> dict:
    path = os.path.join(adapter_dir, "adapter_config.json")
    with open(path, encoding="utf-8") as handle:
        config = json.load(handle)
    if config.get("peft_type") != "LORA":
        raise ValueError(f"Expected peft_type=LORA, got {config.get('peft_type')!r}")
    if config.get("use_dora") or config.get("use_rslora"):
        raise NotImplementedError("Only plain LoRA (alpha/r) is supported; DoRA and RSLoRA are not")
    if config.get("rank_pattern") or config.get("alpha_pattern") or config.get("fan_in_fan_out"):
        raise NotImplementedError("Per-target rank/alpha and transposed LoRA weights are not supported")
    rank, alpha = config.get("r"), config.get("lora_alpha")
    if not isinstance(rank, int) or isinstance(rank, bool) or rank <= 0:
        raise ValueError("LoRA rank must be a positive integer")
    if not isinstance(alpha, (int, float)) or not math.isfinite(alpha) or alpha <= 0:
        raise ValueError("LoRA alpha must be finite and positive")
    return config


def _load_base_weight_map(base_dir: str) -> dict[str, str]:
    """Return {tensor_name: shard_filename}, for sharded or single-file checkpoints."""
    index_path = os.path.join(base_dir, "model.safetensors.index.json")
    if os.path.exists(index_path):
        with open(index_path, encoding="utf-8") as handle:
            return json.load(handle)["weight_map"]

    single_path = os.path.join(base_dir, "model.safetensors")
    if os.path.exists(single_path):
        with safe_open(single_path, framework="pt") as handle:
            return dict.fromkeys(handle.keys(), "model.safetensors")

    raise FileNotFoundError(f"Found neither model.safetensors.index.json nor model.safetensors under {base_dir}")


def _validate_output_directory(base_dir: str, adapter_dir: str, output_dir: str) -> None:
    resolved_output = os.path.realpath(output_dir)
    protected_inputs = {
        os.path.realpath(base_dir),
        os.path.realpath(adapter_dir),
    }
    if any(os.path.commonpath((resolved_output, input_dir)) == input_dir for input_dir in protected_inputs):
        raise ValueError("output directory must be outside the base model and adapter directories")
    if os.path.exists(output_dir):
        raise FileExistsError(f"output directory already exists: {output_dir}")


def merge(base_dir: str, adapter_dir: str, output_dir: str) -> dict:
    _validate_output_directory(base_dir, adapter_dir, output_dir)
    config_path = os.path.join(base_dir, "config.json")
    if os.path.exists(config_path):
        with open(config_path, encoding="utf-8") as handle:
            base_config = json.load(handle)
        if base_config.get("quantization_config") or base_config.get("expert_dtype") in ("fp4", "fp8"):
            raise ValueError("Prepare a floating-point checkpoint with its quantization backend before merging")
    config = _load_adapter_config(adapter_dir)
    adapter = load_file(os.path.join(adapter_dir, "adapter_model.safetensors"))
    weight_map = _load_base_weight_map(base_dir)
    targets = build_lora_merge_plan(adapter, weight_map, rank=config["r"])
    shards = {weight_map[key] for key in targets}
    for shard in sorted(shards):
        if os.path.basename(shard) != shard:
            raise ValueError(f"Expected a checkpoint shard filename, got {shard!r}")
        with safe_open(os.path.join(base_dir, shard), framework="pt") as handle:
            keys = set(handle.keys())
            for key in (key for key in targets if weight_map[key] == shard):
                if key not in keys:
                    raise ValueError(f"Checkpoint index refers to missing tensors: {key}")
                if handle.get_slice(key).get_dtype() not in ("F16", "BF16", "F32"):
                    raise ValueError(f"Decode the quantized base weight before merging: {key}")

    os.makedirs(output_dir)
    for name in os.listdir(base_dir):
        source = os.path.join(base_dir, name)
        if name not in shards and os.path.isfile(source):
            shutil.copy2(source, os.path.join(output_dir, name))
    for shard in sorted(shards):
        with safe_open(os.path.join(base_dir, shard), framework="pt") as handle:
            metadata = handle.metadata()
            keys = list(handle.keys())
            tensors = {key: handle.get_tensor(key) for key in keys}
        for key, factors in targets.items():
            if key in tensors:
                tensors[key] = merge_lora_weight(tensors[key], *factors, config["lora_alpha"] / config["r"])
        save_file(tensors, os.path.join(output_dir, shard), metadata=metadata)
    return {"merged_count": len(targets)}


def main():
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument("--base-model", required=True)
    parser.add_argument("--adapter", required=True)
    parser.add_argument("--output", required=True)
    args = parser.parse_args()
    merge(args.base_model, args.adapter, args.output)


if __name__ == "__main__":
    main()
