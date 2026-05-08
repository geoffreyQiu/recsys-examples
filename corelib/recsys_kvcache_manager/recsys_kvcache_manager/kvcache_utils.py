import math
import os
import time

import numpy as np
import torch
from torchrec.sparse.jagged_tensor import KeyedJaggedTensor
from dataclasses import dataclass, field
from typing import Any, Dict, List, Optional
from abc import ABC, abstractmethod
from enum import Enum


class KVCacheOffloadMode(Enum):
    LAZY = "lazy"
    EAGER = "eager"

@dataclass
class KVLookupResult:
    # batch_size: int
    user_ids: torch.Tensor
    request_id: Optional[str] = None
    # total_history_lengths: torch.Tensor
    cached_start_indices: Optional[torch.Tensor] = None
    cached_lengths: Optional[torch.Tensor] = None
    gpu_cached_start_indices: Optional[torch.Tensor] = None
    gpu_cached_lengths: Optional[torch.Tensor] = None
    host_cached_start_indices: Optional[torch.Tensor] = None
    host_cached_lengths: Optional[torch.Tensor] = None
    
    # new_tokens_upper_bound: int
    token_ids: Optional[torch.Tensor] = None
    token_mask: Optional[torch.Tensor] = None

    extra: Dict[str, Any] = field(default_factory=dict)

    @classmethod
    def merge(cls, lookup_res1, lookup_res2):
        assert torch.equal(lookup_res1.user_ids, lookup_res2.user_ids)
        if lookup_res1.gpu_cached_start_indices is not None and lookup_res1.gpu_cached_lengths is not None:
            assert lookup_res2.host_cached_start_indices is not None and lookup_res2.host_cached_lengths is not None
        
        if lookup_res1.host_cached_start_indices is not None and lookup_res1.host_cached_lengths is not None:
            assert lookup_res2.gpu_cached_start_indices is not None and lookup_res2.gpu_cached_lengths is not None
            res = lookup_res1
            lookup_res1 = lookup_res2
            lookup_res2 = res
        
        # assume lookup_res1 is gpu lookup result, lookup_res2 is host lookup result
        batch_size = lookup_res1.user_ids.size(0)
        cached_start_indices = torch.empty_like(lookup_res1.gpu_cached_start_indices)
        cached_lengths = torch.empty_like(lookup_res1.gpu_cached_lengths)
        for i in range(batch_size):
            cached_start_ind = 0
            cached_len = 0
            if lookup_res2.host_cached_lengths[i] == 0:
                cached_start_ind = lookup_res1.gpu_cached_start_indices[i]
                cached_len = lookup_res1.gpu_cached_lengths[i]
            elif lookup_res1.gpu_cached_lengths[i] == 0:
                assert lookup_res2.host_cached_start_indices[i] == 0, "Host caching from the beginning of the sequence."
                cached_start_ind = lookup_res2.host_cached_start_indices[i]
                cached_len = lookup_res2.host_cached_lengths[i]
            else:
                assert lookup_res2.host_cached_start_indices[i] == 0, "Host caching from the beginning of the sequence."
                assert lookup_res1.gpu_cached_start_indices[i] >= 0, "Invalid gpu cache start ind."

                assert lookup_res1.gpu_cached_start_indices[i] <= lookup_res2.host_cached_lengths[i], "No gaps allowed: GPU cache start index should be smaller than or equal to host cached length."
                cached_len = max(lookup_res2.host_cached_lengths[i], lookup_res1.gpu_cached_start_indices[i] + lookup_res1.gpu_cached_lengths[i]).item()
            
            cached_start_indices[i] = cached_start_ind
            cached_lengths[i] = cached_len

        merged_extra = {}
        merged_extra.update(getattr(lookup_res1, "extra", {}) or {})
        merged_extra.update(getattr(lookup_res2, "extra", {}) or {})

        request_id = lookup_res1.request_id or lookup_res2.request_id
        merged_lookup_result = cls(
            user_ids=lookup_res1.user_ids,
            request_id=request_id,
            # total_history_lengths=lookup_res1.total_history_lengths,
            cached_start_indices=cached_start_indices,
            cached_lengths=cached_lengths,
            gpu_cached_start_indices=lookup_res1.gpu_cached_start_indices,
            gpu_cached_lengths=lookup_res1.gpu_cached_lengths,
            host_cached_start_indices=lookup_res2.host_cached_start_indices,
            host_cached_lengths=lookup_res2.host_cached_lengths,
            token_ids=lookup_res1.token_ids if lookup_res1.token_ids is not None else lookup_res2.token_ids,
            token_mask=lookup_res1.token_mask if lookup_res1.token_mask is not None else lookup_res2.token_mask,
            extra=merged_extra,
        )
        return merged_lookup_result


@dataclass
class KVIndexMeta:
    user_ids: torch.Tensor
    seq_lengths: torch.Tensor


@dataclass
class FlexKVIndexMeta(KVIndexMeta):
    batch_size: int = 0
    request_id: str = ""

    token_ids: Optional[torch.Tensor] = None
    token_mask: Optional[torch.Tensor] = None
    namespaces: Optional[List[str]] = None

    old_cached_lengths: Optional[torch.Tensor] = None
    secondary_get_task_ids: Optional[torch.Tensor] = None
    secondary_matched_lengths: Optional[torch.Tensor] = None
    secondary_hit_mask: Optional[torch.Tensor] = None

    extra: Dict[str, Any] = field(default_factory=dict)