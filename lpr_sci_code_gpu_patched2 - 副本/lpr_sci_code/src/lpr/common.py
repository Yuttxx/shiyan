from __future__ import annotations

import json
import os
import random
from pathlib import Path
from typing import Any, Dict, Iterable, Iterator, List, Optional

import numpy as np
import torch
import yaml


class EasyConfig:
    def __init__(self, data: Dict[str, Any]):
        self._data = data

    def __getattr__(self, item: str) -> Any:
        if item in self._data:
            value = self._data[item]
            if isinstance(value, dict):
                return EasyConfig(value)
            return value
        raise AttributeError(item)

    def to_dict(self) -> Dict[str, Any]:
        return self._data

    def get(self, key: str, default: Any = None) -> Any:
        if key not in self._data:
            return default
        value = self._data[key]
        return EasyConfig(value) if isinstance(value, dict) else value


def load_config(path: str | os.PathLike[str]) -> EasyConfig:
    with open(path, "r", encoding="utf-8") as f:
        cfg = yaml.safe_load(f)
    return EasyConfig(cfg)


def ensure_dir(path: str | os.PathLike[str]) -> Path:
    p = Path(path)
    p.mkdir(parents=True, exist_ok=True)
    return p


def set_seed(seed: int) -> None:
    random.seed(seed)
    np.random.seed(seed)
    torch.manual_seed(seed)
    torch.cuda.manual_seed_all(seed)
    torch.backends.cudnn.deterministic = True
    torch.backends.cudnn.benchmark = False
    try:
        torch.set_num_threads(1)
        torch.set_num_interop_threads(1)
    except Exception:
        pass


def get_device(prefer: Optional[str] = None) -> torch.device:
    if prefer:
        requested = torch.device(prefer)
        if requested.type == "cuda" and not torch.cuda.is_available():
            print("[WARN] Requested CUDA but torch.cuda.is_available() is False. Falling back to CPU.")
            return torch.device("cpu")
        return requested
    return torch.device("cuda" if torch.cuda.is_available() else "cpu")


def save_json(obj: Any, path: str | os.PathLike[str]) -> None:
    with open(path, "w", encoding="utf-8") as f:
        json.dump(obj, f, ensure_ascii=False, indent=2)


def load_json(path: str | os.PathLike[str]) -> Any:
    with open(path, "r", encoding="utf-8") as f:
        return json.load(f)


def write_jsonl(rows: Iterable[Dict[str, Any]], path: str | os.PathLike[str]) -> None:
    with open(path, "w", encoding="utf-8") as f:
        for row in rows:
            f.write(json.dumps(row, ensure_ascii=False) + "\n")


def read_jsonl(path: str | os.PathLike[str]) -> List[Dict[str, Any]]:
    rows: List[Dict[str, Any]] = []
    with open(path, "r", encoding="utf-8") as f:
        for line in f:
            line = line.strip()
            if line:
                rows.append(json.loads(line))
    return rows


def batched(iterable: List[Any], batch_size: int) -> Iterator[List[Any]]:
    for start in range(0, len(iterable), batch_size):
        yield iterable[start : start + batch_size]


def pad_sequences(seqs: List[List[int]], pad_value: int = 0) -> torch.Tensor:
    max_len = max(len(seq) for seq in seqs)
    out = torch.full((len(seqs), max_len), pad_value, dtype=torch.long)
    for i, seq in enumerate(seqs):
        out[i, : len(seq)] = torch.tensor(seq, dtype=torch.long)
    return out


def pad_float_sequences(seqs: List[List[float]], pad_value: float = 0.0) -> torch.Tensor:
    max_len = max(len(seq) for seq in seqs)
    out = torch.full((len(seqs), max_len), pad_value, dtype=torch.float32)
    for i, seq in enumerate(seqs):
        out[i, : len(seq)] = torch.tensor(seq, dtype=torch.float32)
    return out


def sequence_mask(lengths: torch.Tensor, max_len: Optional[int] = None) -> torch.Tensor:
    if max_len is None:
        max_len = int(lengths.max().item())
    idx = torch.arange(max_len, device=lengths.device).unsqueeze(0)
    return idx < lengths.unsqueeze(1)


def softmax_masked(logits: torch.Tensor, mask: torch.Tensor, dim: int = -1) -> torch.Tensor:
    logits = logits.masked_fill(~mask, torch.finfo(logits.dtype).min)
    return torch.softmax(logits, dim=dim)
