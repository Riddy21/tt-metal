# SPDX-FileCopyrightText: © 2026 Tenstorrent USA, Inc.
# SPDX-License-Identifier: Apache-2.0

import torch
from transformers.configuration_utils import PretrainedConfig

import ttnn
from models.demos.deepseek_v3.reference.modeling_deepseek import DeepseekV3YarnRotaryEmbedding
from models.demos.deepseek_v3_d_p.tt.mla.utils import create_balanced_chunk_order, reorder_tensor_chunks


def get_rot_transformation_mat():
    """Generate the rotation transformation matrix for RoPE. Uses a single tile."""
    dhead = ttnn.TILE_SIZE
    rot_emb_matrix = torch.zeros(1, 1, dhead, dhead)
    rot_emb_matrix[..., torch.arange(0, dhead, 2), torch.arange(1, dhead, 2)] = 1
    rot_emb_matrix[..., torch.arange(1, dhead, 2), torch.arange(0, dhead, 2)] = -1
    return rot_emb_matrix


def get_cos_sin_matrix(hf_config):
    """Get cos and sin matrices for rotary positional embeddings.

    HuggingFace returns cos/sin in [max_seq_len, dim] with dim = [t1,..,td//2, t1,..,td//2].
    We convert to Meta-style [t1,t1,..,td//2,td//2] format and return [1, 1, max_seq_len, dim].
    """
    args = {
        "dim": hf_config.qk_rope_head_dim,
        "max_position_embeddings": hf_config.max_seq_len,
        "base": hf_config.rope_theta * 1.0,
        "device": "cpu",
        "scaling_factor": hf_config.rope_scaling["factor"],
        "original_max_position_embeddings": hf_config.rope_scaling["original_max_position_embeddings"],
        "beta_fast": hf_config.rope_scaling["beta_fast"],
        "beta_slow": hf_config.rope_scaling["beta_slow"],
        "mscale": hf_config.rope_scaling["mscale"],
        "mscale_all_dim": hf_config.rope_scaling["mscale_all_dim"],
    }

    reference_rope = DeepseekV3YarnRotaryEmbedding(**args)

    cos = reference_rope.cos_cached
    sin = reference_rope.sin_cached

    # Undo the HF permute to Meta-style
    cos = cos[:, : cos.shape[1] // 2]
    cos = torch.stack((cos, cos), dim=-1).flatten(-2)

    sin = sin[:, : sin.shape[1] // 2]
    sin = torch.stack((sin, sin), dim=-1).flatten(-2)

    cos = cos.unsqueeze(0).unsqueeze(0)  # [1, 1, max_seq_len, dim]
    sin = sin.unsqueeze(0).unsqueeze(0)  # [1, 1, max_seq_len, dim]

    return cos, sin


class RotarySetup:
    """Rotary positional embedding setup for MLA prefill with SP sharding and balanced reordering."""

    def __init__(
        self,
        hf_config: PretrainedConfig,
        mesh_device: ttnn.MeshDevice,
        sp_axis: int = 0,
        is_balanced: bool = False,
    ):
        self.hf_config = hf_config
        self.mesh_device = mesh_device
        self.sp_axis = sp_axis
        self.is_balanced = is_balanced
        self.sp_factor = mesh_device.shape[sp_axis]

    def get_rope_tensors(self, seq_len: int, start_pos: int = 0) -> dict[str, ttnn.Tensor]:
        """Get cos, sin, and transformation matrices sharded over SP axis.

        Args:
            seq_len: number of tokens to build rope for.
            start_pos: global position of the first token (used for chunked prefill,
                where each chunk needs rope values for its absolute global positions).

        If is_balanced, cos/sin are reordered according to balanced chunk order
        before sharding so each SP device gets rope values matching its chunk positions.
        """
        cos_matrix_torch, sin_matrix_torch = get_cos_sin_matrix(self.hf_config)

        end_pos = start_pos + seq_len
        assert (
            end_pos <= self.hf_config.max_seq_len
        ), f"end_pos {end_pos} must be less than or equal to max_seq_len {self.hf_config.max_seq_len}"
        assert (
            not self.is_balanced or start_pos == 0
        ), "is_balanced=True is only supported for start_pos=0 (single-shot prefill)"
        cos_matrix_torch = cos_matrix_torch[..., start_pos:end_pos, :]
        sin_matrix_torch = sin_matrix_torch[..., start_pos:end_pos, :]

        if self.is_balanced:
            chunk_order = create_balanced_chunk_order(self.sp_factor)
            cos_matrix_torch = reorder_tensor_chunks(cos_matrix_torch, chunk_order, seq_dim=2)
            sin_matrix_torch = reorder_tensor_chunks(sin_matrix_torch, chunk_order, seq_dim=2)

        shard_dims = [None, None]
        shard_dims[self.sp_axis] = 2

        cos_matrix = ttnn.from_torch(
            cos_matrix_torch,
            device=self.mesh_device,
            layout=ttnn.TILE_LAYOUT,
            dtype=ttnn.bfloat16,
            mesh_mapper=ttnn.ShardTensor2dMesh(self.mesh_device, dims=shard_dims, mesh_shape=self.mesh_device.shape),
        )
        sin_matrix = ttnn.from_torch(
            sin_matrix_torch,
            device=self.mesh_device,
            layout=ttnn.TILE_LAYOUT,
            dtype=ttnn.bfloat16,
            mesh_mapper=ttnn.ShardTensor2dMesh(self.mesh_device, dims=shard_dims, mesh_shape=self.mesh_device.shape),
        )

        trans_mat_torch = get_rot_transformation_mat()
        trans_matrix = ttnn.from_torch(
            trans_mat_torch,
            device=self.mesh_device,
            layout=ttnn.TILE_LAYOUT,
            dtype=ttnn.bfloat16,
            mesh_mapper=ttnn.ReplicateTensorToMesh(self.mesh_device),
        )

        return {"cos_matrix": cos_matrix, "sin_matrix": sin_matrix, "trans_matrix": trans_matrix}

    def get_rope_tensors_rotated(self, chunk_size_global: int, kv_actual_isl: int) -> dict[str, ttnn.Tensor]:
        """Get cos/sin/trans matrices for the KV-pad-aware rotated chunked path.

        Each chip's rope shard is permuted so that the cos/sin row at chip-local
        position `r` matches the global position of that chip's `r`-th Q row
        after the server-side rotation. Mirrors the per-chip destination math in
        ``ttnn.experimental.deepseek_prefill.update_padded_kv_cache``: pad-fill Q
        rows come first (OLD-slab destination positions in global order), then
        NEW-slab Q rows, then pad rows (rope values for pad rows are arbitrary —
        their outputs are masked by SDPA's rotation logic).

        Args:
            chunk_size_global: global chunk size (one chunk's worth of tokens
                across all sp devices). Per-chip seq = chunk_size_global // sp_factor.
            kv_actual_isl: prior valid global KV length in tokens. Tile-aligned.
                Constraints:
                  * ``kv_actual_isl + chunk_size_global <= max_seq_len``
                  * ``kv_actual_isl % TILE_SIZE == 0``
                  * ``chunk_size_global % (TILE_SIZE * sp_factor) == 0``
        """
        assert not self.is_balanced, "rotated rope is incompatible with is_balanced"
        sp = self.sp_factor
        chunk_local = chunk_size_global // sp
        end_global = kv_actual_isl + chunk_size_global
        assert (
            end_global <= self.hf_config.max_seq_len
        ), f"kv_actual_isl + chunk_size_global ({end_global}) must be <= max_seq_len {self.hf_config.max_seq_len}"
        assert kv_actual_isl % ttnn.TILE_SIZE == 0, f"kv_actual_isl ({kv_actual_isl}) must be tile-aligned"
        assert (
            chunk_size_global % (ttnn.TILE_SIZE * sp) == 0
        ), f"chunk_size_global ({chunk_size_global}) must be a multiple of TILE_SIZE * sp ({ttnn.TILE_SIZE * sp})"

        # Per-chip global position for each Q row in chip-local write order. Mirrors the
        # writer kernel's update_idxt math (and the now-generalized ring_joint_sdpa rotation):
        # each chip writes its chunk_local rows starting at update_idxt, and the cache cell at
        # local row `lr` on chip c holds global position (lr // chunk_local)*chunk_size_global +
        # c*chunk_local + (lr % chunk_local). Slab-aware: handles kv_actual_isl spanning multiple
        # slabs (chips before the boundary jump to the next slab, the boundary chip starts at its
        # offset and may straddle a slab, chips after stay on the current slab). Rope values for
        # rows beyond the valid frontier are don't-care (their Q outputs are masked by SDPA).
        boundary_slab = kv_actual_isl // chunk_size_global
        boundary_chip = (kv_actual_isl // chunk_local) % sp
        boundary_offset = kv_actual_isl % chunk_local

        positions = [[0] * chunk_local for _ in range(sp)]
        for c in range(sp):
            if c < boundary_chip:
                update_idxt = (boundary_slab + 1) * chunk_local
            elif c == boundary_chip:
                update_idxt = boundary_slab * chunk_local + boundary_offset
            else:
                update_idxt = boundary_slab * chunk_local
            for r in range(chunk_local):
                lr = update_idxt + r
                positions[c][r] = (lr // chunk_local) * chunk_size_global + c * chunk_local + (lr % chunk_local)

        cos_matrix_torch, sin_matrix_torch = get_cos_sin_matrix(self.hf_config)

        # Build per-chip slices then concatenate in chip order. Sharding at dim 2
        # along sp_axis then distributes them: rows [c*chunk_local, (c+1)*chunk_local)
        # land on the c-th sp slice.
        per_chip_cos = [cos_matrix_torch[..., positions[c], :] for c in range(sp)]
        per_chip_sin = [sin_matrix_torch[..., positions[c], :] for c in range(sp)]
        cos_matrix_torch = torch.cat(per_chip_cos, dim=2)
        sin_matrix_torch = torch.cat(per_chip_sin, dim=2)

        shard_dims = [None, None]
        shard_dims[self.sp_axis] = 2

        cos_matrix = ttnn.from_torch(
            cos_matrix_torch,
            device=self.mesh_device,
            layout=ttnn.TILE_LAYOUT,
            dtype=ttnn.bfloat16,
            mesh_mapper=ttnn.ShardTensor2dMesh(self.mesh_device, dims=shard_dims, mesh_shape=self.mesh_device.shape),
        )
        sin_matrix = ttnn.from_torch(
            sin_matrix_torch,
            device=self.mesh_device,
            layout=ttnn.TILE_LAYOUT,
            dtype=ttnn.bfloat16,
            mesh_mapper=ttnn.ShardTensor2dMesh(self.mesh_device, dims=shard_dims, mesh_shape=self.mesh_device.shape),
        )

        trans_mat_torch = get_rot_transformation_mat()
        trans_matrix = ttnn.from_torch(
            trans_mat_torch,
            device=self.mesh_device,
            layout=ttnn.TILE_LAYOUT,
            dtype=ttnn.bfloat16,
            mesh_mapper=ttnn.ReplicateTensorToMesh(self.mesh_device),
        )

        return {"cos_matrix": cos_matrix, "sin_matrix": sin_matrix, "trans_matrix": trans_matrix}
