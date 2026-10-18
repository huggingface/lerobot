# Adapted from NVlabs/LongLive at 1b9e348897cafa206fc6dd6feb80b59e2a8b1aa9.
# Copyright (c) 2026 NVIDIA CORPORATION & AFFILIATES. All rights reserved.
# Changes: LeRobot package imports and reference-only runtime integration.
# Long-WAM file attribution; existing upstream notices are retained below.
# SPDX-FileCopyrightText: Copyright (c) 2026 The FastWAM Authors
# SPDX-FileCopyrightText: The DiffSynth-Studio contributors
# SPDX-License-Identifier: MIT AND Apache-2.0
# Provenance: Copied from the source snapshot listed below.
# Source: https://github.com/yuantianyuan01/FastWAM @ 7faa71108368fbb3b6885649f112af607427a2d4 :: src/fastwam/models/wan22/helpers/io.py
# License texts and provenance: see the Long-WAM _core/NOTICE.md.
# Source: https://github.com/modelscope/DiffSynth-Studio @ 974cfa37f27ac55eba3b6d10efa21f876900572d :: diffsynth/core/loader/config.py
# Source: https://github.com/modelscope/DiffSynth-Studio @ 974cfa37f27ac55eba3b6d10efa21f876900572d :: diffsynth/core/loader/file.py
# Changes: Nested DiffSynth-Studio/Wan implementations incorporated through FastWAM retain their Apache-2.0 terms.
# End Long-WAM attribution.

import glob
import hashlib
from dataclasses import dataclass

import torch
from safetensors import safe_open


@dataclass
class ModelConfig:
    """Resolve frozen backbone assets through the standard Hugging Face cache."""

    model_id: str | None = None
    origin_file_pattern: str | None = None
    path: str | None = None

    def download_if_necessary(self):
        if self.path is not None:
            return
        if not self.model_id or not self.origin_file_pattern:
            raise ValueError("Provide a local path or a model_id and file pattern")
        from pathlib import Path

        from huggingface_hub import snapshot_download

        root = Path(self.model_id).expanduser()
        if not root.is_dir():
            pattern = self.origin_file_pattern
            root = Path(
                snapshot_download(
                    self.model_id,
                    allow_patterns=pattern + "*" if pattern.endswith("/") else pattern,
                )
            )
        matches = sorted(glob.glob(str(root / self.origin_file_pattern)))
        if not matches:
            raise FileNotFoundError(f"No {self.origin_file_pattern!r} in {root}")
        self.path = matches[0] if len(matches) == 1 else matches


def load_state_dict(file_path, torch_dtype=None, device="cpu"):
    if isinstance(file_path, list):
        state_dict = {}
        for file_path_ in file_path:
            state_dict.update(load_state_dict(file_path_, torch_dtype=torch_dtype, device=device))
        return state_dict
    if file_path.endswith(".safetensors"):
        return load_state_dict_from_safetensors(file_path, torch_dtype=torch_dtype, device=device)
    return load_state_dict_from_bin(file_path, torch_dtype=torch_dtype, device=device)


def load_state_dict_from_safetensors(file_path, torch_dtype=None, device="cpu"):
    state_dict = {}
    with safe_open(file_path, framework="pt", device=str(device)) as f:
        for key in f.keys():  # noqa: SIM118 — safe_open is not an iterable dictionary.
            value = f.get_tensor(key)
            if torch_dtype is not None:
                value = value.to(torch_dtype)
            state_dict[key] = value
    return state_dict


def load_state_dict_from_bin(file_path, torch_dtype=None, device="cpu"):
    state_dict = torch.load(file_path, map_location=device, weights_only=True)
    if len(state_dict) == 1:
        if "state_dict" in state_dict:
            state_dict = state_dict["state_dict"]
        elif "module" in state_dict:
            state_dict = state_dict["module"]
        elif "model_state" in state_dict:
            state_dict = state_dict["model_state"]
    if torch_dtype is not None:
        for key in state_dict:
            if isinstance(state_dict[key], torch.Tensor):
                state_dict[key] = state_dict[key].to(torch_dtype)
    return state_dict


def _load_keys_dict_from_safetensors(file_path):
    keys_dict = {}
    with safe_open(file_path, framework="pt", device="cpu") as f:
        for key in f.keys():  # noqa: SIM118 — safe_open is not an iterable dictionary.
            keys_dict[key] = f.get_slice(key).get_shape()
    return keys_dict


def _convert_state_dict_to_keys_dict(state_dict):
    keys_dict = {}
    for key, value in state_dict.items():
        if isinstance(value, torch.Tensor):
            keys_dict[key] = list(value.shape)
        else:
            keys_dict[key] = _convert_state_dict_to_keys_dict(value)
    return keys_dict


def _load_keys_dict_from_bin(file_path):
    state_dict = load_state_dict_from_bin(file_path)
    return _convert_state_dict_to_keys_dict(state_dict)


def _load_keys_dict(file_path):
    if isinstance(file_path, list):
        merged = {}
        for path in file_path:
            merged.update(_load_keys_dict(path))
        return merged
    if file_path.endswith(".safetensors"):
        return _load_keys_dict_from_safetensors(file_path)
    return _load_keys_dict_from_bin(file_path)


def _convert_keys_dict_to_single_str(keys_dict, with_shape=True):
    keys = []
    for key, value in keys_dict.items():
        if isinstance(key, str):
            if isinstance(value, dict):
                keys.append(key + "|" + _convert_keys_dict_to_single_str(value, with_shape=with_shape))
            else:
                if with_shape:
                    shape = "_".join(map(str, list(value)))
                    keys.append(key + ":" + shape)
                keys.append(key)
    keys.sort()
    return ",".join(keys)


def hash_model_file(path, with_shape=True):
    keys_dict = _load_keys_dict(path)
    keys_str = _convert_keys_dict_to_single_str(keys_dict, with_shape=with_shape).encode("UTF-8")
    return hashlib.md5(keys_str, usedforsecurity=False).hexdigest()
