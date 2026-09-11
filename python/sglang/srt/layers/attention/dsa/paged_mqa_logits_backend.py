from __future__ import annotations

from enum import Enum

import torch

from sglang.srt.runtime_context import get_platform
from sglang.srt.utils import is_hip


class DSAPagedMQALogitsBackend(Enum):
    DEEPGEMM = "deepgemm"
    CUTEDSL = "cutedsl"
    AITER = "aiter"
    TORCH = "torch"

    def is_deepgemm(self) -> bool:
        return self == DSAPagedMQALogitsBackend.DEEPGEMM

    def is_cutedsl(self) -> bool:
        return self == DSAPagedMQALogitsBackend.CUTEDSL

    def is_aiter(self) -> bool:
        return self == DSAPagedMQALogitsBackend.AITER

    def is_torch(self) -> bool:
        return self == DSAPagedMQALogitsBackend.TORCH

    @staticmethod
    def resolve(value: str) -> DSAPagedMQALogitsBackend:
        if is_hip():
            if value not in ("auto", "aiter"):
                raise ValueError(
                    f"dsa_paged_mqa_logits_backend={value!r} is not supported on "
                    "ROCm; only 'aiter' is implemented."
                )
            return DSAPagedMQALogitsBackend.AITER

        if value == "auto":
            # DeepGEMM's CUDA paged-MQA kernels start at SM90.  Keep the
            # explicit ``deepgemm`` option strict, while making auto usable
            # on SM80/SM86 fallback machines.
            if not torch.cuda.is_available():
                return DSAPagedMQALogitsBackend.DEEPGEMM
            major, _ = torch.cuda.get_device_capability()
            if major < 9:
                return DSAPagedMQALogitsBackend.TORCH
            return DSAPagedMQALogitsBackend.DEEPGEMM
        if value == "deepgemm":
            return DSAPagedMQALogitsBackend.DEEPGEMM
        if value == "aiter":
            raise ValueError("dsa_paged_mqa_logits_backend='aiter' requires ROCm.")
        if value == "cutedsl":
            if not get_platform().is_sm100:
                raise ValueError(
                    "dsa_paged_mqa_logits_backend='cutedsl' requires SM100 (Blackwell)."
                )
            return DSAPagedMQALogitsBackend.CUTEDSL
        if value == "torch":
            return DSAPagedMQALogitsBackend.TORCH
        raise ValueError(f"Unknown dsa_paged_mqa_logits_backend: {value!r}")
