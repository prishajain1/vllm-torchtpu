# Copyright 2026 Google LLC
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.
"""Scratchpad layout, stage arena packing, and Pallas BlockSpecs for Qwen3.8-2.4T."""

from __future__ import annotations

import math
from typing import TYPE_CHECKING, Any

import jax
import jax.experimental.pallas as pl
import jax.experimental.pallas.tpu as pltpu
import jax.numpy as jnp

from vllm_torchtpu.megakernel.dma import ArenaSlice, VmemArena

if TYPE_CHECKING:
    from .shapes import Qwen38Config

SCRATCH_LIMIT_BYTES = 64 * 1024 * 1024  # 64 MiB per core
SMEM_LIMIT_BYTES = 1024 * 1024  # 1 MiB scalar memory limit
_PAD2_SIZE: int = 2
_MIN_2D_NDIM: int = 2
_MOE_WEIGHT_NDIM: int = 6


def _nbytes(shape: tuple[int, ...], dtype: jnp.dtype | str | type) -> int:
    """Return total bytes for an array of the given shape and element type."""
    return int(math.prod(shape)) * int(jnp.dtype(dtype).itemsize)


def build_stage_arena(cfg: Qwen38Config) -> tuple[VmemArena, dict[str, ArenaSlice]]:
    """Pack stage-disjoint down-projection weight buffers onto a shared `VmemArena`.

    All three stage-disjoint packed FP4 down-projection buffers share the
    trailing row width `(cfg.H // 2,)` in `uint8`:
    - Attention stage: `wo_buf` `(cfg.Q_R * cfg.D, cfg.H // 2)`
    - GDN stage: `wout_buf` `(cfg.Z_R, cfg.H // 2)`
    - MoE stage: `wse2_buf` `(cfg.SE_R, cfg.H // 2)`
    """
    shapes = {
        "wo_buf": (cfg.Q_R * cfg.D, cfg.H // 2),
        "wout_buf": (cfg.Z_R, cfg.H // 2),
        "wse2_buf": (cfg.SE_R, cfg.H // 2),
    }
    row_tile = 32
    cap = max(
        ((r + row_tile - 1) // row_tile) * row_tile * (((c + 127) // 128) * 128)
        for r, c in shapes.values()
    )
    arena = VmemArena(capacity_bytes=cap)
    wo_buf = arena.allocate("wo_buf", shapes["wo_buf"], jnp.uint8)
    wout_buf = arena.allocate(
        "wout_buf", shapes["wout_buf"], jnp.uint8, replaces=("wo_buf",)
    )
    wse2_buf = arena.allocate(
        "wse2_buf", shapes["wse2_buf"], jnp.uint8, replaces=("wout_buf",)
    )
    arena.release("wse2_buf")
    slices = {
        "wo_buf": wo_buf,
        "wout_buf": wout_buf,
        "wse2_buf": wse2_buf,
    }
    return arena, slices


def make_scratch_specs(cfg: Qwen38Config, *, interpret: bool = False) -> dict[str, Any]:
    """Build the scratchpad dictionary for `pl.pallas_call`.

    Composes `VmemArena` for stage-disjoint down-projection weight buffers and
    allocates explicit ping-pong scratch for the local 2-level `hier=4` all-reduce.
    """
    b = cfg.B
    h = cfg.H
    d = cfg.D
    dcp = cfg.DCP
    q_r = cfg.Q_R
    k_r = cfg.K_R
    qkv = cfg.QKV
    z_r = cfg.Z_R
    vh_r = cfg.VH_R
    kd = cfg.KD
    vd = cfg.VD
    i_r = cfg.I_R
    se_r = cfg.SE_R
    g = cfg.fp4_group
    h_tile = cfg.h_tile
    hier_g = min(cfg.hier_group, cfg.R)
    num_groups = max(1, cfg.R // hier_g)

    arena, _ = build_stage_arena(cfg)

    return {
        # Stage-disjoint down-projection weight arena (wo_buf, wout_buf, wse2_buf)
        "stage_arena_u8": arena.scratch_spec(interpret=bool(interpret)),
        # Local 2-level hier=4 all-reduce buffers
        "ar_send": pltpu.VMEM((2, max(1, hier_g - 1), b, h), jnp.bfloat16),
        "ar_recv": pltpu.VMEM((2, max(1, hier_g - 1), b, h), jnp.bfloat16),
        "ar_stage_send": pltpu.VMEM((2, max(1, num_groups - 1), b, h), jnp.float32),
        "ar_stage_recv": pltpu.VMEM((2, max(1, num_groups - 1), b, h), jnp.float32),
        "ar_ssem1": pltpu.SemaphoreType.DMA((2, max(1, hier_g - 1))),
        "ar_rsem1": pltpu.SemaphoreType.DMA((2, max(1, hier_g - 1))),
        "ar_ssem2": pltpu.SemaphoreType.DMA((2, max(1, num_groups - 1))),
        "ar_rsem2": pltpu.SemaphoreType.DMA((2, max(1, num_groups - 1))),
        "b_sem": pltpu.SemaphoreType.REGULAR((4,)),
        # Persistent residual & normalized hidden buffers
        "x_cur": pltpu.VMEM((b, h), jnp.bfloat16),
        "x_norm": pltpu.VMEM((b, h), jnp.bfloat16),
        # Streaming H-tile FP4 weight + scale ping-pong buffers
        "wqkv_buf": pltpu.VMEM((2, h_tile, cfg.ATT_QKV_R // 2), jnp.uint8),
        "wqkv_s_buf": pltpu.VMEM((2, h_tile // g, cfg.ATT_QKV_R), jnp.bfloat16),
        "wo_s_buf": pltpu.VMEM(((q_r * d) // g, h), jnp.bfloat16),
        "win_buf": pltpu.VMEM((2, h_tile, (qkv + z_r) // 2), jnp.uint8),
        "win_s_buf": pltpu.VMEM((2, h_tile // g, qkv + z_r), jnp.bfloat16),
        "wba_buf": pltpu.VMEM((h, 2 * vh_r), jnp.bfloat16),
        "wconv_buf": pltpu.VMEM((cfg.conv_kernel, qkv), jnp.bfloat16),
        "wout_s_buf": pltpu.VMEM((z_r // g, h), jnp.bfloat16),
        "wgate_buf": pltpu.VMEM((h, cfg.E), jnp.bfloat16),
        "wsegate_buf": pltpu.VMEM((h, 1), jnp.bfloat16),
        "wse13_buf": pltpu.VMEM((2, h_tile, se_r), jnp.uint8),
        "wse13_s_buf": pltpu.VMEM((2, h_tile // g, 2 * se_r), jnp.bfloat16),
        "wse2_s_buf": pltpu.VMEM((se_r // g, h), jnp.bfloat16),
        # Double-buffered routed expert weights & scales (2 slots for K=8 stream)
        "we13_buf": pltpu.VMEM((2, h_tile, i_r), jnp.uint8),
        "we13_s_buf": pltpu.VMEM((2, h_tile // g, 2 * i_r), jnp.bfloat16),
        "we2_buf": pltpu.VMEM((2, i_r, h // 2), jnp.uint8),
        "we2_s_buf": pltpu.VMEM((2, i_r // g, h), jnp.bfloat16),
        # GDN recurrent + conv state ping-pong buffers (2 slots)
        "rec_buf": pltpu.VMEM((2, b, vh_r, kd, vd), jnp.float32),
        "conv_buf": pltpu.VMEM((2, b, cfg.conv_kernel - 1, qkv), jnp.bfloat16),
        # DCP8 attention KV page ping-pong + query/LSE cross-rank exchange buffers
        "kv_page_buf": pltpu.VMEM((2, 2, k_r, 4, d, cfg.page_size), jnp.float8_e4m3fn),
        "kv_write_buf": pltpu.VMEM((2, k_r, 4, d, 4), jnp.float8_e4m3fn),
        "q_local_send": pltpu.VMEM((max(1, dcp - 1), b, q_r, d), jnp.bfloat16),
        "q_dcp_recv": pltpu.VMEM((dcp, b, q_r, d), jnp.bfloat16),
        "lse_part_send": pltpu.VMEM(
            (max(1, dcp - 1), b, dcp * q_r, d + 2), jnp.float32
        ),
        "lse_part_recv": pltpu.VMEM((dcp, b, dcp * q_r, d + 2), jnp.float32),
        # Matmul output accumulator scratch
        "fp4_out_buf": pltpu.VMEM(
            (b, max(h, cfg.ATT_QKV_R, qkv + z_r, 2 * se_r, 2 * i_r)), jnp.float32
        ),
        # DMA semaphores
        "w_sem": pltpu.SemaphoreType.DMA((4,)),
        "state_sem": pltpu.SemaphoreType.DMA((4,)),
        "kv_sem": pltpu.SemaphoreType.DMA((4,)),
        "dcp_q_ssem": pltpu.SemaphoreType.DMA((max(1, dcp - 1),)),
        "dcp_q_rsem": pltpu.SemaphoreType.DMA((max(1, dcp - 1),)),
        "dcp_lse_ssem": pltpu.SemaphoreType.DMA((max(1, dcp - 1),)),
        "dcp_lse_rsem": pltpu.SemaphoreType.DMA((max(1, dcp - 1),)),
    }


def _padded_vmem_bytes(shape: tuple[int, ...], itemsize: int) -> int:
    """Compute aligned scratchpad bytes with trailing (8/32, 128) tile padding."""
    if len(shape) >= _MIN_2D_NDIM:
        r_tile = 32 if itemsize == 1 else 8
        r_pad = ((int(shape[-2]) + r_tile - 1) // r_tile) * r_tile
        c_pad = ((int(shape[-1]) + 127) // 128) * 128
        elems = int(math.prod(shape[:-2])) * r_pad * c_pad
    elif len(shape) == 1:
        elems = ((int(shape[0]) + 127) // 128) * 128
    else:
        elems = 1
    return elems * int(itemsize)


def scratch_footprint(cfg: Qwen38Config) -> dict[str, int | float | bool]:
    """Compute aligned byte footprint of scratch/scalar buffers and limits."""
    specs = make_scratch_specs(cfg)
    breakdown: dict[str, int] = {}
    total = 0
    raw_total = 0
    for name, spec in specs.items():
        if hasattr(spec, "shape") and hasattr(spec, "dtype"):
            try:
                dt = jnp.dtype(spec.dtype)
            except TypeError:
                continue
            sh = tuple(int(d) for d in spec.shape)
            raw_nb = int(math.prod(sh)) * int(dt.itemsize)
            nb = _padded_vmem_bytes(sh, int(dt.itemsize))
            breakdown[name] = nb
            total += nb
            raw_total += raw_nb
    arena, slices = build_stage_arena(cfg)
    unpacked_stage_bytes = sum(s.size_bytes for s in slices.values())
    smem_bytes = total_scalar_bytes(cfg)
    return {
        **breakdown,
        "stage_arena_high_water_bytes": arena.peak_bytes,
        "stage_arena_saved_bytes": unpacked_stage_bytes - arena.peak_bytes,
        "raw_total_bytes": raw_total,
        "total_bytes": total,
        "total_mib": round(total / (1024 * 1024), 3),
        "limit_bytes": SCRATCH_LIMIT_BYTES,
        "scalar_bytes": smem_bytes,
        "scalar_limit_bytes": SMEM_LIMIT_BYTES,
        "fits_in_scalar_limit": smem_bytes < SMEM_LIMIT_BYTES,
        "fits_in_limit": (total < SCRATCH_LIMIT_BYTES)
        and (smem_bytes < SMEM_LIMIT_BYTES),
    }


def total_scalar_bytes(cfg: Qwen38Config) -> int:
    """Compute total scalar-memory input bytes (`pos` + `page_table`)."""
    pos_bytes = cfg.B * 4
    pt_bytes = cfg.NATT * cfg.B * cfg.max_pages_per_seq * 4
    return pos_bytes + pt_bytes


# Weight tensors whose H dimension is tiled into (H // h_tile, h_tile) for 4D/5D DMA
_H_TILED_4D_KEYS = frozenset({"wqkv", "w_inproj", "w_se13"})
_H_TILED_4D_SCALE_KEYS = frozenset({"wqkv_s", "w_inproj_s", "w_se13_s"})
_H_TILED_5D_KEYS = frozenset({"w_e13"})
_H_TILED_5D_SCALE_KEYS = frozenset({"w_e13_s"})
_PAD2_AXIS2_KEYS = (
    _H_TILED_4D_KEYS
    | _H_TILED_4D_SCALE_KEYS
    | _H_TILED_5D_KEYS
    | _H_TILED_5D_SCALE_KEYS
)


def normalize_weights_for_pallas(
    weights: dict[str, jax.Array], cfg: Qwen38Config
) -> dict[str, jax.Array]:
    """Reshape H-tiled weights into explicit `(n_htiles, h_tile, ...)` axes."""
    n_ht = cfg.H // cfg.h_tile
    g_ht = cfg.h_tile // cfg.fp4_group
    out: dict[str, jax.Array] = {}
    for k, arr in weights.items():
        v = arr
        if k in _H_TILED_4D_KEYS:
            v = v.reshape(v.shape[0], v.shape[1], n_ht, cfg.h_tile, v.shape[3])
        elif k in _H_TILED_4D_SCALE_KEYS:
            v = v.reshape(v.shape[0], v.shape[1], n_ht, g_ht, v.shape[3])
        elif k in _H_TILED_5D_KEYS:
            v = v.reshape(
                v.shape[0], v.shape[1], v.shape[2], n_ht, cfg.h_tile, v.shape[4]
            )
        elif k in _H_TILED_5D_SCALE_KEYS:
            v = v.reshape(v.shape[0], v.shape[1], v.shape[2], n_ht, g_ht, v.shape[4])

        if k in _PAD2_AXIS2_KEYS:
            ax = 3 if v.ndim == _MOE_WEIGHT_NDIM else 2
            if v.shape[ax] == 1:
                v = jnp.repeat(v, _PAD2_SIZE, axis=ax)
        out[k] = v
    return out


def _unpad_weight(k: str, v: jax.Array, n_ht: int) -> jax.Array:
    """Remove axis padding added to satisfy Pallas tiling requirements."""
    if k not in _PAD2_AXIS2_KEYS:
        return v
    if k in {"wqkv", "wqkv_s", "w_inproj", "w_inproj_s", "w_se13", "w_se13_s"}:
        if n_ht == 1 and v.shape[2] == _PAD2_SIZE:
            return v[:, :, :1, ...]
    elif k in {"w_e13", "w_e13_s"} and n_ht == 1 and v.shape[3] == _PAD2_SIZE:
        return v[:, :, :, :1, ...]
    return v


def _untile_weight(k: str, v: jax.Array) -> jax.Array:
    """Collapse tiled H dimensions back to canonical rank."""
    if k in _H_TILED_4D_KEYS or k in _H_TILED_4D_SCALE_KEYS:
        return v.reshape(v.shape[0], v.shape[1], v.shape[2] * v.shape[3], v.shape[4])
    if k in _H_TILED_5D_KEYS or k in _H_TILED_5D_SCALE_KEYS:
        return v.reshape(
            v.shape[0],
            v.shape[1],
            v.shape[2],
            v.shape[3] * v.shape[4],
            v.shape[5],
        )
    return v


def denormalize_weights_from_pallas(
    norm_weights: dict[str, jax.Array], cfg: Qwen38Config
) -> dict[str, jax.Array]:
    """Restore normalized Pallas weight dict back to canonical shapes."""
    n_ht = cfg.H // cfg.h_tile
    out: dict[str, jax.Array] = {}
    for k, arr in norm_weights.items():
        v = _unpad_weight(k, arr, n_ht)
        out[k] = _untile_weight(k, v)
    return out


_RESIDENT_WEIGHT_KEYS = frozenset(
    {
        "in_norm",
        "post_norm",
        "final_norm",
        "q_norm",
        "k_norm",
        "a_log",
        "dt_bias",
        "gdn_norm",
    }
)


def make_io_specs(
    weights: dict[str, jax.Array],
    *,
    has_forced_routing: bool = False,
) -> tuple[Any, Any]:
    """Construct `in_specs` and `out_specs` for the single-step `pl.pallas_call`.

    Small routing metadata (`pos`, `page_table`, and optional `forced_top_ids`)
    reside in scalar memory; small per-layer norm/decay vectors
    (`_RESIDENT_WEIGHT_KEYS`) reside in vector scratchpad; large state pools (`pool`,
    `conv`, `rec`) and all projection/MoE weights stay in `pl.ANY` (HBM) and are
    streamed via explicit DMA.
    """
    w_specs = {
        k: pl.BlockSpec(
            memory_space=pltpu.VMEM if k in _RESIDENT_WEIGHT_KEYS else pl.ANY
        )
        for k in weights
    }
    base_in = [
        pl.BlockSpec(memory_space=pltpu.VMEM),  # x_in: (B, H) bf16
        pl.BlockSpec(memory_space=pltpu.SMEM),  # pos: (B,) int32
        pl.BlockSpec(
            memory_space=pltpu.SMEM
        ),  # page_table: (NATT, B, max_pages_per_seq)
        pl.BlockSpec(memory_space=pl.ANY),  # pool: (num_pages, 2, K_R, 4, D, page_size)
        pl.BlockSpec(memory_space=pl.ANY),  # conv: (NGDN, B, conv_kernel-1, QKV)
        pl.BlockSpec(memory_space=pl.ANY),  # rec: (NGDN, B, VH_R, KD, VD)
        w_specs,
    ]
    if has_forced_routing:
        base_in.append(pl.BlockSpec(memory_space=pltpu.SMEM))  # forced_top_ids
    in_specs = tuple(base_in)
    out_specs = (
        pl.BlockSpec(memory_space=pltpu.VMEM),  # x_out: (B, H) bf16
        pl.BlockSpec(memory_space=pl.ANY),  # pool_out
        pl.BlockSpec(memory_space=pl.ANY),  # conv_out
        pl.BlockSpec(memory_space=pl.ANY),  # rec_out
    )
    return in_specs, out_specs


def assert_no_all_gather(hlo_text: str, *, context: str = "") -> None:
    """Fail if the lowered HLO/StableHLO text contains any `all-gather` instruction."""
    for line in hlo_text.splitlines():
        s = line.strip()
        if not s or s.startswith(("//", "#")):
            continue
        if "all-gather" in s or "all_gather" in s:
            prefix = f"[{context}] " if context else ""
            msg = f"{prefix}Forbidden all-gather collective found in HLO: {s}"
            raise AssertionError(msg)
