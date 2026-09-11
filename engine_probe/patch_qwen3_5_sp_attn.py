#!/usr/bin/env python3
"""Patch an installed verl so Qwen3.5 Ulysses SP works with non-flash attention backends.

verl only installs the Ulysses all-to-all into
`transformers.integrations.flash_attention._flash_attention_forward`. With
`attn_implementation=sdpa` that hook is never reached, so every full_attention layer
attends only inside its own rank's contiguous 1/sp slice of the sequence.

Idempotent. `--check` verifies without writing.
"""

import argparse
import base64
import importlib.util
import os
import sys

FN_B64 = "def _packed_segment_bounds(cu_seqlens_cpu, cu_seqlens, total_len: int) -> list[int]:
    """Boundaries of the packed samples inside a gathered (global) sequence of ``total_len``.

    ``cu_seqlens`` is the unsliced offsets tensor the engine passes down, already extended
    with the sequence-parallel pad when there is one (see ``transformer_impl.py``). Prefer
    the cpu copy -- reading the cuda one back would sync on every layer.
    """
    bounds = cu_seqlens_cpu if cu_seqlens_cpu is not None else cu_seqlens
    if bounds is None:
        return [0, total_len]

    raw = [int(x) for x in bounds.tolist()]
    if raw[0] != 0 or raw[-1] > total_len:
        raise ValueError(f"cu_seqlens {raw[0]}..{raw[-1]} does not describe a sequence of {total_len} tokens")

    bounds = [0]
    for offset in raw[1:]:
        if offset > bounds[-1]:  # drop empty samples
            bounds.append(offset)
    if bounds[-1] < total_len:
        bounds.append(total_len)  # trailing sequence-parallel padding
    return bounds


def qwen3_5_attn_forward(
    self,
    hidden_states: torch.Tensor,
    position_embeddings: tuple[torch.Tensor, torch.Tensor],
    attention_mask: Optional[torch.Tensor] = None,
    past_key_values=None,
    **kwargs,
):
    """Backend-agnostic Ulysses SP for Qwen3.5 full-attention layers.

    The generic hook in ``monkey_patch.py`` only replaces
    ``transformers.integrations.flash_attention._flash_attention_forward``, so it is dead
    code whenever ``attn_implementation`` is not flash attention (e.g. ``sdpa``). Without
    an all-to-all each rank attends only inside its own contiguous 1/sp slice of the
    sequence -- a silent correctness bug, not a precision one.

    This mirrors ``verl/models/transformers/qwen2.py``: gather the sequence / scatter the
    heads around whichever attention interface the config selects. RoPE is applied before
    the all-to-all, on the local shard, because cos/sin are built from the local (but
    globally-valued) position ids.

    Packing is handled by looping over the *global* ``cu_seqlens`` segments with a causal,
    mask-free call per segment. HF builds its own block-causal mask from the local shard's
    position ids, which describes the wrong rows/columns once the sequence is gathered, and
    the global dense equivalent would be ``total_nnz**2`` (~16 GB at 126k tokens).

    Flash-attention backends are left alone: ``monkey_patch`` also replaces
    ``_flash_attention_forward``, which already does the all-to-all there.
    """
    from transformers.modeling_utils import ALL_ATTENTION_FUNCTIONS
    from transformers.models.qwen3_5.modeling_qwen3_5 import (
        apply_rotary_pos_emb,
        eager_attention_forward,
        repeat_kv,
    )

    from verl.utils.ulysses import gather_heads_scatter_seq, gather_seq_scatter_heads

    cu_seqlens = kwargs.pop("cu_seqlens", None)
    cu_seqlens_cpu = kwargs.pop("cu_seqlens_cpu", None)

    input_shape = hidden_states.shape[:-1]
    hidden_shape = (*input_shape, -1, self.head_dim)

    query_states, gate = torch.chunk(self.q_proj(hidden_states).view(*input_shape, -1, self.head_dim * 2), 2, dim=-1)
    gate = gate.reshape(*input_shape, -1)

    query_states = self.q_norm(query_states.view(hidden_shape)).transpose(1, 2)
    key_states = self.k_norm(self.k_proj(hidden_states).view(hidden_shape)).transpose(1, 2)
    value_states = self.v_proj(hidden_states).view(hidden_shape).transpose(1, 2)

    cos, sin = position_embeddings
    query_states, key_states = apply_rotary_pos_emb(query_states, key_states, cos, sin)

    if past_key_values is not None:
        key_states, value_states = past_key_values.update(key_states, value_states, self.layer_idx)

    attn_impl = self.config._attn_implementation
    ulysses_sp_size = get_ulysses_sequence_parallel_world_size()
    # flash backends get their all-to-all from the `_flash_attention_forward` hook
    do_all_to_all = ulysses_sp_size > 1 and "flash" not in str(attn_impl)

    num_key_value_groups = self.num_key_value_groups
    if do_all_to_all:
        if attention_mask is not None and cu_seqlens is None and cu_seqlens_cpu is None:
            # a mask means the batch is packed (or padded); without the global boundaries the
            # segment loop below would let sample i attend to sample i-1. Fail loudly.
            raise NotImplementedError(
                "Qwen3.5 Ulysses SP needs `cu_seqlens` to rebuild the packing boundaries after the "
                f"all-to-all, but got only a local-shard mask of shape {tuple(attention_mask.shape)}."
            )
        # repeat kv so the head count is divisible by sp (same rule as _ulysses_flash_attention_forward)
        repeats = max(ulysses_sp_size // key_states.size(1), 1)
        key_states = repeat_kv(key_states, repeats)
        value_states = repeat_kv(value_states, repeats)

        # (bsz, n_head, seq_len/sp, head_dim) -> (bsz, n_head/sp, seq_len, head_dim)
        query_states = gather_seq_scatter_heads(query_states, seq_dim=2, head_dim=1)
        key_states = gather_seq_scatter_heads(key_states, seq_dim=2, head_dim=1)
        value_states = gather_seq_scatter_heads(value_states, seq_dim=2, head_dim=1)

        # sdpa/eager re-expand kv using module.num_key_value_groups; after the repeat and
        # scatter above that ratio is no longer the one stored on the module.
        num_key_value_groups = query_states.size(1) // key_states.size(1)

    attention_interface = ALL_ATTENTION_FUNCTIONS.get_interface(attn_impl, eager_attention_forward)
    attn_common = dict(
        dropout=0.0 if not self.training else self.attention_dropout,
        scaling=self.scaling,
        **kwargs,
    )

    orig_groups = self.num_key_value_groups
    self.num_key_value_groups = num_key_value_groups
    try:
        if do_all_to_all:
            segments = _packed_segment_bounds(cu_seqlens_cpu, cu_seqlens, query_states.size(2))
            outputs = []
            attn_weights = None
            for start, end in zip(segments[:-1], segments[1:], strict=True):
                # attention_mask=None -> sdpa/eager take their own `is_causal` path, which is
                # exactly right inside one packed sample and keeps the kernel O(n) in memory
                out, _ = attention_interface(
                    self,
                    query_states[:, :, start:end],
                    key_states[:, :, start:end],
                    value_states[:, :, start:end],
                    None,
                    **attn_common,
                )
                outputs.append(out)
            attn_output = outputs[0] if len(outputs) == 1 else torch.cat(outputs, dim=1)
        else:
            attn_output, attn_weights = attention_interface(
                self,
                query_states,
                key_states,
                value_states,
                attention_mask,
                **attn_common,
            )
    finally:
        self.num_key_value_groups = orig_groups

    if do_all_to_all:
        # (bsz, seq_len, n_head/sp, head_dim) -> (bsz, seq_len/sp, n_head, head_dim)
        attn_output = gather_heads_scatter_seq(attn_output, seq_dim=1, head_dim=2)

    attn_output = attn_output.reshape(*input_shape, -1).contiguous()
    attn_output = attn_output * torch.sigmoid(gate)
    return self.o_proj(attn_output), attn_weights"
FN_SRC = base64.b64decode(FN_B64).decode()

ANCHOR_FN = "def qwen3_5_decoder_layer_forward("

# the decoder layer pops cu_seqlens out of kwargs; the attention wrapper needs it back
DL_OLD_B64 = "ICAgIGVsaWYgZ2V0YXR0cihzZWxmLCAibGF5ZXJfdHlwZSIsIGdldGF0dHIoc2VsZiwgImJsb2NrX3R5cGUiLCBOb25lKSkgPT0gImZ1bGxfYXR0ZW50aW9uIjoKICAgICAgICBoaWRkZW5fc3RhdGVzLCBfID0gc2VsZi5zZWxmX2F0dG4oCiAgICAgICAgICAgIGhpZGRlbl9zdGF0ZXM9aGlkZGVuX3N0YXRlcywKICAgICAgICAgICAgYXR0ZW50aW9uX21hc2s9YXR0ZW50aW9uX21hc2ssCiAgICAgICAgICAgIHBvc2l0aW9uX2lkcz1wb3NpdGlvbl9pZHMsCiAgICAgICAgICAgIHBhc3Rfa2V5X3ZhbHVlcz1wYXN0X2tleV92YWx1ZXMsCiAgICAgICAgICAgIHBvc2l0aW9uX2VtYmVkZGluZ3M9cG9zaXRpb25fZW1iZWRkaW5ncywKICAgICAgICAgICAgKiprd2FyZ3MsCiAgICAgICAgKQ=="
DL_NEW_B64 = "ICAgIGVsaWYgZ2V0YXR0cihzZWxmLCAibGF5ZXJfdHlwZSIsIGdldGF0dHIoc2VsZiwgImJsb2NrX3R5cGUiLCBOb25lKSkgPT0gImZ1bGxfYXR0ZW50aW9uIjoKICAgICAgICBhdHRuX2t3YXJncyA9IGt3YXJncwogICAgICAgIGlmIGdldF91bHlzc2VzX3NlcXVlbmNlX3BhcmFsbGVsX3dvcmxkX3NpemUoKSA+IDE6CiAgICAgICAgICAgICMgYHF3ZW4zXzVfYXR0bl9mb3J3YXJkYCBuZWVkcyB0aGUgZ2xvYmFsICh1bnNsaWNlZCkgcGFja2luZyBib3VuZGFyaWVzIHRvIGtlZXAKICAgICAgICAgICAgIyBhdHRlbnRpb24gYmxvY2stZGlhZ29uYWwgYWZ0ZXIgdGhlIGFsbC10by1hbGwgLS0gSEYncyBvd24gbWFzayBpcyBidWlsdCBmcm9tIHRoZQogICAgICAgICAgICAjIGxvY2FsIHNoYXJkIGFuZCBpcyBtZWFuaW5nbGVzcyB0aGVyZS4gT25seSBjb25zdW1lZCB3aGVuIHRoYXQgcGF0Y2ggaXMgaW5zdGFsbGVkLgogICAgICAgICAgICBhdHRuX2t3YXJncyA9IHsqKmt3YXJncywgImN1X3NlcWxlbnMiOiBjdV9zZXFsZW5zLCAiY3Vfc2VxbGVuc19jcHUiOiBjdV9zZXFsZW5zX2NwdX0KICAgICAgICBoaWRkZW5fc3RhdGVzLCBfID0gc2VsZi5zZWxmX2F0dG4oCiAgICAgICAgICAgIGhpZGRlbl9zdGF0ZXM9aGlkZGVuX3N0YXRlcywKICAgICAgICAgICAgYXR0ZW50aW9uX21hc2s9YXR0ZW50aW9uX21hc2ssCiAgICAgICAgICAgIHBvc2l0aW9uX2lkcz1wb3NpdGlvbl9pZHMsCiAgICAgICAgICAgIHBhc3Rfa2V5X3ZhbHVlcz1wYXN0X2tleV92YWx1ZXMsCiAgICAgICAgICAgIHBvc2l0aW9uX2VtYmVkZGluZ3M9cG9zaXRpb25fZW1iZWRkaW5ncywKICAgICAgICAgICAgKiphdHRuX2t3YXJncywKICAgICAgICAp"
DL_OLD = base64.b64decode(DL_OLD_B64).decode()
DL_NEW = base64.b64decode(DL_NEW_B64).decode()

IMPORT_OLD = """        from transformers.models.qwen3_5.modeling_qwen3_5 import (
            Qwen3_5DecoderLayer,"""
IMPORT_NEW = """        from transformers.models.qwen3_5.modeling_qwen3_5 import (
            Qwen3_5Attention,
            Qwen3_5DecoderLayer,"""

IMPORT_MOE_OLD = """        from transformers.models.qwen3_5_moe.modeling_qwen3_5_moe import (
            Qwen3_5MoeDecoderLayer,"""
IMPORT_MOE_NEW = """        from transformers.models.qwen3_5_moe.modeling_qwen3_5_moe import (
            Qwen3_5MoeAttention,
            Qwen3_5MoeDecoderLayer,"""

IMPORT_VERL_OLD = """        from verl.models.transformers.qwen3_5 import (
            fast_pos_embed_interpolate,
            forward_with_normal_backend,
            qwen3_5_base_forward,"""
IMPORT_VERL_NEW = """        from verl.models.transformers.qwen3_5 import (
            fast_pos_embed_interpolate,
            forward_with_normal_backend,
            qwen3_5_attn_forward,
            qwen3_5_base_forward,"""

REG_OLD = """        if ulysses_sp_size > 1:
            patch_vlm_for_ulysses_input_slicing(Qwen3_5TextModel)
            patch_vlm_for_ulysses_input_slicing(Qwen3_5MoeTextModel)
"""
REG_NEW = """        if ulysses_sp_size > 1:
            patch_vlm_for_ulysses_input_slicing(Qwen3_5TextModel)
            patch_vlm_for_ulysses_input_slicing(Qwen3_5MoeTextModel)

            # Step 3: full-attention layers need the all-to-all for every backend, not just
            # flash attention. The generic `_flash_attention_forward` hook below is never
            # reached under e.g. `attn_implementation=sdpa`, which would silently confine
            # attention to each rank's own 1/sp slice of the sequence.
            Qwen3_5Attention.forward = qwen3_5_attn_forward
            Qwen3_5MoeAttention.forward = qwen3_5_attn_forward
            print(f"Monkey patch {model.__class__.__name__} attention layer for Ulysses SP")
"""


def verl_dir():
    spec = importlib.util.find_spec("verl")
    return os.path.dirname(spec.origin)


def patch_model_file(path, check):
    src = open(path).read()
    if "def qwen3_5_attn_forward(" in src and DL_NEW in src:
        return "already patched"
    if check:
        return "MISSING qwen3_5_attn_forward"
    assert ANCHOR_FN in src, f"anchor not found in {path}"
    assert src.count(DL_OLD) == 1, f"expected 1 self_attn call site in {path}, got {src.count(DL_OLD)}"
    open(path + ".orig", "w").write(src)
    # FN_SRC is rstripped; PEP8 wants two blank lines before the anchor def
    new = src.replace(ANCHOR_FN, FN_SRC + "\n\n\n" + ANCHOR_FN, 1).replace(DL_OLD, DL_NEW, 1)
    open(path, "w").write(new)
    return "patched"


def patch_monkey_file(path, check):
    src = open(path).read()
    done = "Qwen3_5Attention.forward = qwen3_5_attn_forward" in src
    if done:
        return "already patched"
    if check:
        return "MISSING attention registration"
    new = src
    for old, rep in (
        (IMPORT_OLD, IMPORT_NEW),
        (IMPORT_MOE_OLD, IMPORT_MOE_NEW),
        (IMPORT_VERL_OLD, IMPORT_VERL_NEW),
        (REG_OLD, REG_NEW),
    ):
        assert new.count(old) == 1, f"expected exactly 1 occurrence of:\n{old}\ngot {new.count(old)}"
        new = new.replace(old, rep, 1)
    open(path + ".orig", "w").write(src)
    open(path, "w").write(new)
    return "patched"


def main():
    ap = argparse.ArgumentParser()
    ap.add_argument("--check", action="store_true")
    a = ap.parse_args()
    d = verl_dir()
    m = os.path.join(d, "models", "transformers", "qwen3_5.py")
    p = os.path.join(d, "models", "transformers", "monkey_patch.py")
    r1 = patch_model_file(m, a.check)
    r2 = patch_monkey_file(p, a.check)
    print(f"{m}: {r1}")
    print(f"{p}: {r2}")
    if a.check:
        ok = r1 == "already patched" and r2 == "already patched"
        # runtime proof: the class attribute really gets swapped
        import torch  # noqa: F401
        from transformers.models.qwen3_5.modeling_qwen3_5 import (
            Qwen3_5Attention,
            Qwen3_5TextConfig,
            Qwen3_5TextModel,
        )

        from verl.models.transformers.monkey_patch import apply_monkey_patch

        # heads must be divisible by ulysses_sp_size (apply_monkey_patch asserts it)
        cfg = Qwen3_5TextConfig(
            vocab_size=64, hidden_size=128, intermediate_size=128, num_hidden_layers=2,
            num_attention_heads=8, num_key_value_heads=8, head_dim=16,
            layer_types=["full_attention"] * 2, max_position_embeddings=32,
        )
        cfg._attn_implementation = "sdpa"
        mdl = Qwen3_5TextModel(cfg)
        cfg.model_type = "qwen3_5"
        apply_monkey_patch(mdl, ulysses_sp_size=8, use_remove_padding=True, use_fused_kernels=False)
        name = Qwen3_5Attention.forward.__name__
        print(f"Qwen3_5Attention.forward -> {name}")
        ok = ok and name == "qwen3_5_attn_forward"
        sys.exit(0 if ok else 1)


if __name__ == "__main__":
    main()
