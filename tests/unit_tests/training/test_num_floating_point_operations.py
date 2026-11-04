# Copyright (c) 2026 NVIDIA CORPORATION & AFFILIATES. All rights reserved.

"""FLOP accounting for the standard and hybrid model paths.

The standard path must use the decoder's final attention type for every MTP depth; the
hybrid path must cost KDA, the MLA output gate and attention residuals from the arguments.
"""

from types import SimpleNamespace

import pytest

from megatron.training.training import num_floating_point_operations


def _make_args(**overrides):
    args = SimpleNamespace(
        attention_output_gate=True,
        decoder_seq_length=None,
        experimental_attention_variant="gdn",
        ffn_hidden_size=16,
        group_query_attention=True,
        hidden_size=8,
        hybrid_layer_pattern=None,
        kv_channels=4,
        linear_attention_freq=4,
        linear_conv_kernel_dim=4,
        linear_key_head_dim=2,
        linear_num_key_heads=1,
        linear_num_value_heads=2,
        linear_value_head_dim=3,
        moe_ffn_hidden_size=10,
        moe_latent_size=None,
        moe_layer_freq=[0, 1] * 20,
        moe_router_topk=2,
        moe_shared_expert_intermediate_size=4,
        mtp_num_layers=None,
        multi_latent_attention=False,
        num_attention_heads=2,
        num_experts=4,
        num_layers=40,
        num_query_groups=1,
        padded_vocab_size=32,
        seq_length=8,
        swiglu=True,
    )
    for name, value in overrides.items():
        setattr(args, name, value)
    cfg = SimpleNamespace(tokenizer=SimpleNamespace(padded_vocab_size=args.padded_vocab_size))
    return args, cfg


def _expected_flops(tokens, squared_lengths, layer_counts, mtp_depth):
    """Hand-calculated coefficients for the fixed small model in _make_args."""
    gdn, full, dense, moe = layer_counts
    # All coefficients include forward/backward (3) and multiply/add (2).
    # Full: Q/K/V/gate widths 8/4/4/8, output 8 -> hidden 8.
    full_projections = 1536  # 6 * (8 * (8 + 4 + 4 + 8) + 8 * 8)
    full_core = 48  # 6 * query width 8, including causal masking.
    # GDN: input width 20, convolution 40, recurrence 72, output projection 48.
    gdn_attention = 1920  # 6 * (8 * 20 + 40 + 72 + 48)
    dense_mlp = 2304  # SwiGLU: 6 * hidden 8 * intermediate 16 * 3.
    moe_mlp = 3456  # Routed and shared: 6 * 8 * 3 * (10 * topk 2 + 4).
    mtp_norms_and_projection = 912  # 6 * (3 * 8 + 2 * 8 * 8).
    logits = 1536  # 6 * hidden 8 * vocabulary 32.
    return (
        tokens
        * (
            gdn * gdn_attention
            + full * full_projections
            + dense * dense_mlp
            + moe * moe_mlp
            + mtp_depth * mtp_norms_and_projection
            + (1 + mtp_depth) * logits
        )
        + squared_lengths * full * full_core
    )


def _batch_stats(layout):
    if layout == "bshd":
        # Three ordinary sequences of length eight, using the default arguments.
        return {}, 24, 192
    # Unequal packed subsequences [3, 5, 7], shorter than the BSHD allocation.
    return {"total_real_tokens_in_batch": 15, "seqlen_squared_sum_in_batch": 83}, 15, 83


@pytest.mark.parametrize("layout", ["bshd", "thd"])
@pytest.mark.parametrize("pattern_form", ["int", "list"])
@pytest.mark.parametrize(
    "num_layers,mtp_depth,expected_counts",
    [
        # Counts are (GDN, full attention, dense MLP, MoE MLP).
        # Forty decoder layers end in full attention and MoE.
        (40, None, (30, 10, 20, 20)),
        (40, 0, (30, 10, 20, 20)),
        (40, 1, (30, 11, 20, 21)),
        (40, 2, (30, 12, 20, 22)),
        # Three decoder layers end in GDN and a dense MLP. MTP stays GDN,
        # even though extending the integer frequency would next produce full attention.
        (3, None, (3, 0, 2, 1)),
        (3, 0, (3, 0, 2, 1)),
        (3, 1, (4, 0, 3, 1)),
        (3, 2, (5, 0, 4, 1)),
    ],
)
def test_mtp_repeats_final_decoder_attention_type(
    layout, pattern_form, num_layers, mtp_depth, expected_counts
):
    pattern = [1, 1, 1, 0] * 10 if num_layers == 40 else [1, 1, 1]
    original_pattern = pattern.copy()
    args, cfg = _make_args(
        num_layers=num_layers,
        mtp_num_layers=mtp_depth,
        linear_attention_freq=4 if pattern_form == "int" else pattern,
        moe_layer_freq=[0, 1] * 20 if num_layers == 40 else [0, 1, 0],
    )
    stats, tokens, squared_lengths = _batch_stats(layout)

    actual = num_floating_point_operations(args, cfg, batch_size=3, **stats)

    assert actual == _expected_flops(tokens, squared_lengths, expected_counts, mtp_depth or 0)
    # Keep T fixed and change only Q to isolate the number of full-attention layers.
    merged = num_floating_point_operations(
        args,
        cfg,
        batch_size=3,
        total_real_tokens_in_batch=tokens,
        seqlen_squared_sum_in_batch=tokens**2,
    )
    assert merged - actual == 48 * expected_counts[1] * (tokens**2 - squared_lengths)
    # A list describes decoder layers only; counting MTP must not append to it.
    assert pattern == original_pattern


@pytest.mark.parametrize("layout", ["bshd", "thd"])
@pytest.mark.parametrize("mtp_depth", [None, 0, 1, 2])
def test_plain_attention_and_dense_mlp_flops_are_unchanged(layout, mtp_depth):
    args, cfg = _make_args(
        experimental_attention_variant=None,
        linear_attention_freq=None,
        num_layers=3,
        num_experts=None,
        mtp_num_layers=mtp_depth,
    )
    stats, tokens, squared_lengths = _batch_stats(layout)
    depth = mtp_depth or 0

    actual = num_floating_point_operations(args, cfg, batch_size=3, **stats)

    assert actual == _expected_flops(tokens, squared_lengths, (0, 3 + depth, 3 + depth, 0), depth)


def _make_hybrid_args(**overrides):
    """A three-layer hybrid stack: one KDA, one MLA and one MoE layer."""
    hybrid = dict(
        hybrid_layer_pattern="K+E",
        experimental_attention_variant="kda",
        linear_attention_freq=None,
        # KimiDeltaAttention requires the same head geometry for K and V.
        linear_key_head_dim=2,
        linear_value_head_dim=2,
        linear_num_key_heads=1,
        linear_num_value_heads=1,
        moe_layer_freq=1,
        num_layers=3,
        multi_latent_attention=True,
        q_lora_rank=4,
        kv_lora_rank=4,
        qk_head_dim=2,
        qk_pos_emb_head_dim=2,
        v_head_dim=2,
        mamba_state_dim=4,
        mamba_head_dim=2,
        mamba_num_groups=1,
        mamba_num_heads=2,
        gdp_num_householder=1,
        kda_f_lora_rank=None,
        kda_gate_lora_rank=None,
        attention_output_gate=False,
        enable_attention_residuals=False,
        attn_res_block_layers=None,
        dsa_indexer_n_heads=1,
        dsa_indexer_head_dim=1,
        dsa_indexer_topk=1,
        dsa_indexer_loss_coeff=0.0,
        dsa_indexer_skip_topk_offset=0,
        dsa_indexer_topk_freq=1,
    )
    hybrid.update(overrides)
    return _make_args(**hybrid)


def _hybrid_flops(**overrides):
    args, cfg = _make_hybrid_args(**overrides)
    return num_floating_point_operations(args, cfg, batch_size=3)


def test_hybrid_kda_flops_follow_the_configured_head_count():
    # The hybrid path used to leave kda_num_qk_heads / kda_num_v_heads at their
    # defaults (16) whatever --linear-num-key-heads said, undercounting KDA models.
    narrow = _hybrid_flops(linear_num_key_heads=1, linear_num_value_heads=1)
    wide = _hybrid_flops(linear_num_key_heads=8, linear_num_value_heads=8)
    wider = _hybrid_flops(linear_num_key_heads=16, linear_num_value_heads=16)
    assert narrow < wide < wider
    # KDA FLOPs are linear in the head count: 8 -> 16 adds more than 1 -> 8.
    assert wider - wide > wide - narrow


def test_hybrid_mla_flops_count_the_output_gate():
    assert _hybrid_flops(attention_output_gate=True) > _hybrid_flops(attention_output_gate=False)


def test_hybrid_flops_count_attention_residuals():
    plain = _hybrid_flops()
    with_residuals = _hybrid_flops(enable_attention_residuals=True, attn_res_block_layers=1)
    assert with_residuals > plain
