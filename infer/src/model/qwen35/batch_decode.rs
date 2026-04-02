//! Batched decode for Qwen3.5: process multiple requests in one forward pass.
//!
//! Hybrid architecture: 8 full attention layers use FlashInfer HD256 paged decode,
//! 24 linear attention layers use batched recurrent kernels (conv1d + GDR) via pointer arrays.

use anyhow::Result;
use cudarc::driver::CudaSlice;

use super::forward::Qwen35State;
use super::weights::{
    FullAttentionLayer, LayerKind, LinearAttentionLayer, Qwen35Model, TransformerBlock35,
};
use crate::flashinfer_metadata::FlashInferDecodeMetadata;
use crate::model::ModelForward;
use crate::ops;
use crate::paged_kv::PagedKVPool;
use crate::tensor::{DeviceContext, HiddenStates};

// ── Sub-structs ─────────────────────────────────────────────────────────────

/// Buffers shared across all layer types: embedding, residuals, final norm.
pub(crate) struct CommonBufs {
    pub(super) hidden_out: HiddenStates,
    pub(super) normed: HiddenStates,
    pub(super) embedding_out: HiddenStates,
    pub(super) o_buf: HiddenStates,
    pub(super) attn_results: HiddenStates,
    pub(super) hidden_mid: HiddenStates,
}

// SAFETY: Exclusively accessed from the single scheduler inference thread.
unsafe impl Send for CommonBufs {}

impl CommonBufs {
    fn set_batch_size(&mut self, bs: usize) {
        self.hidden_out.seq_len = bs;
        self.normed.seq_len = bs;
        self.o_buf.seq_len = bs;
        self.attn_results.seq_len = bs;
        self.hidden_mid.seq_len = bs;
    }
}

/// Buffers for full attention layers (HD256, paged).
pub(crate) struct FullAttnBufs {
    pub(super) q_full_batch: HiddenStates,
    pub(super) q_batch: HiddenStates,
    pub(super) k_batch: HiddenStates,
    pub(super) v_batch: HiddenStates,
    pub(super) attn_output: HiddenStates,
}

// SAFETY: Exclusively accessed from the single scheduler inference thread.
unsafe impl Send for FullAttnBufs {}

impl FullAttnBufs {
    fn set_batch_size(&mut self, bs: usize) {
        self.q_full_batch.seq_len = bs;
        self.q_batch.seq_len = bs;
        self.k_batch.seq_len = bs;
        self.v_batch.seq_len = bs;
        self.attn_output.seq_len = bs;
    }
}

/// Buffers for linear attention layers (conv1d + GDR recurrent).
pub(crate) struct RecurrentBufs {
    pub(super) qkv_batch: HiddenStates,
    pub(super) z_batch: HiddenStates,
    pub(super) b_batch: HiddenStates,
    pub(super) a_batch: HiddenStates,
    /// Per-layer GPU pointer arrays for conv1d state.
    /// Pre-uploaded before decode body to enable future CUDA Graph capture.
    pub(super) conv_state_ptrs_per_layer: Vec<CudaSlice<u64>>,
    /// Per-layer GPU pointer arrays for GDR state.
    pub(super) gdr_state_ptrs_per_layer: Vec<CudaSlice<u64>>,
    /// Shared host staging buffer for pointer array uploads.
    pub(super) conv_state_ptrs_host: Vec<u64>,
    pub(super) gdr_state_ptrs_host: Vec<u64>,
    pub(super) qkv_conv_batch: HiddenStates,
    pub(super) gdr_out_batch: HiddenStates,
    pub(super) normed_gated: HiddenStates,
}

// SAFETY: Exclusively accessed from the single scheduler inference thread.
unsafe impl Send for RecurrentBufs {}

impl RecurrentBufs {
    fn set_batch_size(&mut self, bs: usize) {
        self.qkv_batch.seq_len = bs;
        self.z_batch.seq_len = bs;
        self.b_batch.seq_len = bs;
        self.a_batch.seq_len = bs;
        self.qkv_conv_batch.seq_len = bs;
        self.gdr_out_batch.seq_len = bs;
        self.normed_gated.seq_len = bs;
    }
}

/// Buffers for MLP (gate/up/down projections).
pub(crate) struct MlpBufs {
    pub(super) gate_out: HiddenStates,
    pub(super) up_out: HiddenStates,
    pub(super) act_out: HiddenStates,
}

// SAFETY: Exclusively accessed from the single scheduler inference thread.
unsafe impl Send for MlpBufs {}

impl MlpBufs {
    fn set_batch_size(&mut self, bs: usize) {
        self.gate_out.seq_len = bs;
        self.up_out.seq_len = bs;
        self.act_out.seq_len = bs;
    }
}

// ── Outer container ─────────────────────────────────────────────────────────

/// Pre-allocated buffers for batched decode, reused across steps.
pub struct BatchDecodeBuffers35 {
    pub(super) common: CommonBufs,
    pub(super) attn: FullAttnBufs,
    pub(super) recurrent: RecurrentBufs,
    pub(super) mlp: MlpBufs,

    // ── Logits + sampling ──
    pub(super) logits_batch: Option<HiddenStates>,
    pub(super) argmax_out: CudaSlice<i32>,
    pub(super) argmax_host: Vec<i32>,

    // ── Token IDs ──
    token_ids_gpu: CudaSlice<i32>,
    token_ids_scratch: Vec<i32>,

    // ── FlashInfer metadata (for full attention layers) ──
    pub(crate) metadata: FlashInferDecodeMetadata,

    max_batch_size: usize,
}

// SAFETY: Exclusively accessed from the single scheduler inference thread.
unsafe impl Send for BatchDecodeBuffers35 {}

impl BatchDecodeBuffers35 {
    #[allow(clippy::too_many_arguments)]
    pub(crate) fn new(
        ctx: &DeviceContext,
        hidden_dim: usize,
        q_proj_dim: usize, // num_q_heads * 256 * 2 (includes gate)
        q_dim: usize,      // num_q_heads * 256
        kv_dim: usize,     // num_kv_heads * 256
        inter_dim: usize,
        qkv_dim: usize, // linear attention QKV dim
        z_dim: usize,   // linear attention Z dim
        b_dim: usize,   // linear attention B dim (num_value_heads)
        max_batch_size: usize,
        num_qheads: usize,
        max_total_pages: usize,
        num_linear_layers: usize,
    ) -> Result<Self> {
        let common = CommonBufs {
            hidden_out: HiddenStates::zeros(ctx, hidden_dim, max_batch_size)?,
            normed: HiddenStates::zeros(ctx, hidden_dim, max_batch_size)?,
            embedding_out: HiddenStates::zeros(ctx, hidden_dim, max_batch_size)?,
            o_buf: HiddenStates::zeros(ctx, hidden_dim, max_batch_size)?,
            attn_results: HiddenStates::zeros(ctx, hidden_dim, max_batch_size)?,
            hidden_mid: HiddenStates::zeros(ctx, hidden_dim, max_batch_size)?,
        };

        let attn = FullAttnBufs {
            q_full_batch: HiddenStates::zeros(ctx, q_proj_dim, max_batch_size)?,
            q_batch: HiddenStates::zeros(ctx, q_dim, max_batch_size)?,
            k_batch: HiddenStates::zeros(ctx, kv_dim, max_batch_size)?,
            v_batch: HiddenStates::zeros(ctx, kv_dim, max_batch_size)?,
            attn_output: HiddenStates::zeros(ctx, q_dim, max_batch_size)?,
        };

        // Per-layer pointer arrays enable future CUDA Graph capture by moving
        // all H2D pointer uploads before the graph-capturable section.
        let mut conv_ptrs = Vec::with_capacity(num_linear_layers);
        let mut gdr_ptrs = Vec::with_capacity(num_linear_layers);
        for _ in 0..num_linear_layers {
            conv_ptrs.push(
                ctx.stream
                    .alloc_zeros::<u64>(max_batch_size)
                    .map_err(|e| anyhow::anyhow!("Alloc conv_state_ptrs_per_layer: {e}"))?,
            );
            gdr_ptrs.push(
                ctx.stream
                    .alloc_zeros::<u64>(max_batch_size)
                    .map_err(|e| anyhow::anyhow!("Alloc gdr_state_ptrs_per_layer: {e}"))?,
            );
        }

        let recurrent = RecurrentBufs {
            qkv_batch: HiddenStates::zeros(ctx, qkv_dim, max_batch_size)?,
            z_batch: HiddenStates::zeros(ctx, z_dim, max_batch_size)?,
            b_batch: HiddenStates::zeros(ctx, b_dim, max_batch_size)?,
            a_batch: HiddenStates::zeros(ctx, b_dim, max_batch_size)?,
            conv_state_ptrs_per_layer: conv_ptrs,
            gdr_state_ptrs_per_layer: gdr_ptrs,
            conv_state_ptrs_host: vec![0u64; max_batch_size],
            gdr_state_ptrs_host: vec![0u64; max_batch_size],
            qkv_conv_batch: HiddenStates::zeros(ctx, qkv_dim, max_batch_size)?,
            gdr_out_batch: HiddenStates::zeros(ctx, z_dim, max_batch_size)?,
            normed_gated: HiddenStates::zeros(ctx, z_dim, max_batch_size)?,
        };

        let mlp = MlpBufs {
            gate_out: HiddenStates::zeros(ctx, inter_dim, max_batch_size)?,
            up_out: HiddenStates::zeros(ctx, inter_dim, max_batch_size)?,
            act_out: HiddenStates::zeros(ctx, inter_dim, max_batch_size)?,
        };

        Ok(Self {
            common,
            attn,
            recurrent,
            mlp,

            logits_batch: None,
            argmax_out: ctx
                .stream
                .alloc_zeros(max_batch_size)
                .map_err(|e| anyhow::anyhow!("Alloc argmax_out: {e}"))?,
            argmax_host: vec![0i32; max_batch_size],

            token_ids_gpu: ctx
                .stream
                .alloc_zeros(max_batch_size)
                .map_err(|e| anyhow::anyhow!("Alloc token_ids_gpu: {e}"))?,
            token_ids_scratch: Vec::with_capacity(max_batch_size),

            metadata: FlashInferDecodeMetadata::new(
                ctx,
                max_batch_size,
                max_total_pages,
                num_qheads,
            )?,

            max_batch_size,
        })
    }

    fn set_batch_size(&mut self, bs: usize) {
        debug_assert!(bs <= self.max_batch_size);
        self.common.set_batch_size(bs);
        self.attn.set_batch_size(bs);
        self.recurrent.set_batch_size(bs);
        self.mlp.set_batch_size(bs);
    }
}

impl Qwen35Model {
    /// Batched decode: process B tokens from B different requests in one pass.
    /// Falls back to sequential forward_decode() for non-paged path.
    pub fn decode_batch_contiguous(
        &self,
        tokens: &[u32],
        states: &mut [Qwen35State],
        slot_indices: &[usize],
    ) -> Result<()> {
        for (i, &token) in tokens.iter().enumerate() {
            self.forward_decode(token, &mut states[slot_indices[i]])?;
        }
        Ok(())
    }

    /// Batched decode with paged KV for full attention, per-request recurrent for linear.
    pub fn decode_batch(
        &self,
        tokens: &[u32],
        states: &mut [Qwen35State],
        slot_indices: &[usize],
        skip_logit_scatter: bool,
        paged_kv_pool: &mut PagedKVPool,
        bufs: &mut BatchDecodeBuffers35,
    ) -> Result<()> {
        let batch_size = tokens.len();
        debug_assert_eq!(batch_size, slot_indices.len());
        if batch_size == 0 {
            return Ok(());
        }
        debug_assert!(batch_size <= bufs.max_batch_size);

        let c = &self.config;
        let num_heads = c.num_attention_heads;
        let num_kv_heads = c.num_key_value_heads;
        let head_dim = c.head_dim; // 256
        let page_size = 1;

        bufs.set_batch_size(batch_size);

        // ── Pre-step: metadata H2D + FlashInfer plan + embedding ──

        bufs.token_ids_scratch.clear();
        bufs.token_ids_scratch
            .extend(tokens.iter().map(|&x| x as i32));
        self.ctx
            .stream
            .memcpy_htod(&bufs.token_ids_scratch, &mut bufs.token_ids_gpu)
            .map_err(|e| anyhow::anyhow!("H2D token_ids: {e}"))?;

        let reallocated = bufs
            .metadata
            .update(&self.ctx, paged_kv_pool, slot_indices)?;
        let _ = reallocated; // No CUDA graph cache to invalidate

        bufs.metadata.plan_hd256(
            &self.ctx,
            batch_size,
            num_heads,
            num_kv_heads,
            page_size,
            head_dim,
        )?;

        bufs.common.embedding_out.seq_len = batch_size;

        // Lazy-init logits buffer
        if bufs.logits_batch.is_none() {
            let vocab_size = self.embed_tokens.rows;
            bufs.logits_batch = Some(HiddenStates::zeros(
                &self.ctx,
                vocab_size,
                bufs.max_batch_size,
            )?);
        }

        // ── Pre-upload all recurrent state pointer arrays ──
        // Moving all H2D before the forward pass enables future CUDA Graph capture.
        {
            use cudarc::driver::DevicePtrMut;
            let mut linear_idx = 0usize;
            for layer in &self.layers {
                if matches!(layer.attn, LayerKind::LinearAttention(_)) {
                    for (b, &si) in slot_indices.iter().enumerate() {
                        let layer_state =
                            &mut states[si].recurrent_state.layers[linear_idx];
                        let (conv_ptr, _) =
                            layer_state.conv_state.data.device_ptr_mut(&self.ctx.stream);
                        let (gdr_ptr, _) =
                            layer_state.state.device_ptr_mut(&self.ctx.stream);
                        bufs.recurrent.conv_state_ptrs_host[b] = conv_ptr as u64;
                        bufs.recurrent.gdr_state_ptrs_host[b] = gdr_ptr as u64;
                    }
                    self.ctx
                        .stream
                        .memcpy_htod(
                            &bufs.recurrent.conv_state_ptrs_host[..batch_size],
                            &mut bufs.recurrent.conv_state_ptrs_per_layer[linear_idx],
                        )
                        .map_err(|e| {
                            anyhow::anyhow!("H2D conv_state_ptrs layer {linear_idx}: {e}")
                        })?;
                    self.ctx
                        .stream
                        .memcpy_htod(
                            &bufs.recurrent.gdr_state_ptrs_host[..batch_size],
                            &mut bufs.recurrent.gdr_state_ptrs_per_layer[linear_idx],
                        )
                        .map_err(|e| {
                            anyhow::anyhow!("H2D gdr_state_ptrs layer {linear_idx}: {e}")
                        })?;
                    linear_idx += 1;
                }
            }
        }

        // ── Forward pass ──
        self.decode_batch_body(bufs, states, slot_indices, paged_kv_pool, batch_size)?;

        // Scatter per-slot logits when needed (non-greedy fallback)
        if !skip_logit_scatter {
            let logits = bufs.logits_batch.as_ref().unwrap();
            for (b, &si) in slot_indices.iter().enumerate() {
                ops::extract_vec_into(
                    &self.ctx,
                    logits,
                    b,
                    &mut states[si].decode_bufs.logits_scratch,
                )?;
                states[si].base.prefill_logits = None;
            }
        }

        Ok(())
    }

    fn decode_batch_body(
        &self,
        bufs: &mut BatchDecodeBuffers35,
        states: &mut [Qwen35State],
        slot_indices: &[usize],
        kv_pool: &PagedKVPool,
        batch_size: usize,
    ) -> Result<()> {
        let c = &self.config;
        let eps = c.rms_norm_eps;

        // Embedding
        ops::embedding_batch(
            &self.ctx,
            &self.embed_tokens,
            &bufs.token_ids_gpu,
            &mut bufs.common.embedding_out,
        )?;

        let hidden_ptr = &mut bufs.common.embedding_out as *mut HiddenStates;

        let mut full_idx = 0usize;
        let mut linear_idx = 0usize;

        for layer in &self.layers {
            let hidden = unsafe { &mut *hidden_ptr };
            match &layer.attn {
                LayerKind::FullAttention(attn) => {
                    self.decode_batch_full_attn_layer(
                        layer, attn, hidden, bufs, kv_pool, full_idx, batch_size,
                    )?;
                    full_idx += 1;
                }
                LayerKind::LinearAttention(attn) => {
                    self.decode_batch_linear_attn_layer(
                        layer,
                        attn,
                        hidden,
                        bufs,
                        states,
                        slot_indices,
                        linear_idx,
                        batch_size,
                    )?;
                    linear_idx += 1;
                }
            }
        }

        // Final norm (offset variant) + logits GEMM
        let hidden = unsafe { &*hidden_ptr };
        ops::rms_norm_batch_offset_into(
            &self.ctx,
            hidden,
            &self.norm,
            eps,
            &mut bufs.common.normed,
        )?;
        let logits_buf = bufs.logits_batch.as_mut().unwrap();
        logits_buf.seq_len = batch_size;
        ops::gemm_into(
            &self.ctx,
            &self.embed_tokens,
            &bufs.common.normed,
            logits_buf,
        );

        Ok(())
    }

    #[allow(clippy::too_many_arguments)]
    fn decode_batch_full_attn_layer(
        &self,
        layer: &TransformerBlock35,
        attn: &FullAttentionLayer,
        hidden: &mut HiddenStates,
        bufs: &mut BatchDecodeBuffers35,
        kv_pool: &PagedKVPool,
        full_idx: usize,
        batch_size: usize,
    ) -> Result<()> {
        let c = &self.config;
        let eps = c.rms_norm_eps;
        let num_heads = c.num_attention_heads;
        let num_kv_heads = c.num_key_value_heads;
        let head_dim = c.head_dim;
        let page_size = 1;

        // 1. Input RMSNorm (offset variant)
        ops::rms_norm_batch_offset_into(
            &self.ctx,
            hidden,
            &layer.input_layernorm,
            eps,
            &mut bufs.common.normed,
        )?;

        // 2. QKV projections (batched GEMM)
        ops::gemm_into(
            &self.ctx,
            &attn.q_proj,
            &bufs.common.normed,
            &mut bufs.attn.q_full_batch,
        );
        ops::gemm_into(
            &self.ctx,
            &attn.k_proj,
            &bufs.common.normed,
            &mut bufs.attn.k_batch,
        );
        ops::gemm_into(
            &self.ctx,
            &attn.v_proj,
            &bufs.common.normed,
            &mut bufs.attn.v_batch,
        );

        // 3. Decode prep: QK-norm (1+w) + partial RoPE + paged KV write
        ops::decode_prep_paged_hd256(
            &self.ctx,
            &bufs.attn.q_full_batch,
            &mut bufs.attn.q_batch,
            &bufs.attn.k_batch,
            &bufs.attn.v_batch,
            &attn.q_norm,
            &attn.k_norm,
            &self.cos_cache,
            &self.sin_cache,
            &bufs.metadata.positions,
            kv_pool,
            full_idx,
            &bufs.metadata.kv_indices,
            &bufs.metadata.kv_indptr,
            &bufs.metadata.kv_last_page_len,
            num_heads,
            num_kv_heads,
            page_size,
            c.rotary_dim,
            eps,
        )?;

        // 4. FlashInfer HD256 attention
        ops::flashinfer_run_layer_hd256(
            &self.ctx,
            &bufs.attn.q_batch,
            kv_pool,
            full_idx,
            &bufs.metadata.kv_indptr,
            &bufs.metadata.kv_indices,
            &bufs.metadata.kv_last_page_len,
            &mut bufs.attn.attn_output,
            &mut bufs.metadata.flashinfer_ws,
            num_heads,
            num_kv_heads,
            page_size,
            head_dim,
        )?;

        // 5. Apply sigmoid gate
        ops::attention_gate_paged_hd256(
            &self.ctx,
            &bufs.attn.q_full_batch,
            &mut bufs.attn.attn_output,
            num_heads,
        );

        // 6. O projection
        ops::gemm_into(
            &self.ctx,
            &attn.o_proj,
            &bufs.attn.attn_output,
            &mut bufs.common.attn_results,
        );

        // 7. Residual + post-attention norm + MLP
        self.decode_batch_mlp(layer, hidden, bufs, batch_size)?;

        Ok(())
    }

    #[allow(clippy::too_many_arguments)]
    fn decode_batch_linear_attn_layer(
        &self,
        layer: &TransformerBlock35,
        attn: &LinearAttentionLayer,
        hidden: &mut HiddenStates,
        bufs: &mut BatchDecodeBuffers35,
        states: &mut [Qwen35State],
        slot_indices: &[usize],
        linear_idx: usize,
        batch_size: usize,
    ) -> Result<()> {
        let c = &self.config;
        let eps = c.rms_norm_eps;

        // 1. Input RMSNorm (offset variant)
        ops::rms_norm_batch_offset_into(
            &self.ctx,
            hidden,
            &layer.input_layernorm,
            eps,
            &mut bufs.common.normed,
        )?;

        // 2. Batched projections (GEMM)
        ops::gemm_into(
            &self.ctx,
            &attn.in_proj_qkv,
            &bufs.common.normed,
            &mut bufs.recurrent.qkv_batch,
        );
        ops::gemm_into(
            &self.ctx,
            &attn.in_proj_z,
            &bufs.common.normed,
            &mut bufs.recurrent.z_batch,
        );
        ops::gemm_into(
            &self.ctx,
            &attn.in_proj_b,
            &bufs.common.normed,
            &mut bufs.recurrent.b_batch,
        );
        ops::gemm_into(
            &self.ctx,
            &attn.in_proj_a,
            &bufs.common.normed,
            &mut bufs.recurrent.a_batch,
        );

        // 3. Batched conv1d + GDR using pre-uploaded per-layer pointer arrays.
        // H2D uploads were done in decode_batch() before this body runs.
        {
            // Batched conv1d decode: one kernel launch for all B requests
            ops::conv1d_decode_batch_into(
                &self.ctx,
                &bufs.recurrent.qkv_batch,
                &attn.conv1d_weight,
                &mut bufs.recurrent.conv_state_ptrs_per_layer[linear_idx],
                &mut bufs.recurrent.qkv_conv_batch,
                c.linear_conv_kernel_dim,
                batch_size,
            );

            // Batched GDR decode: one kernel launch for all B requests
            ops::gdr_decode_batch_into(
                &self.ctx,
                &bufs.recurrent.qkv_conv_batch,
                &bufs.recurrent.b_batch,
                &bufs.recurrent.a_batch,
                &attn.dt_bias,
                &attn.a_log,
                &mut bufs.recurrent.gdr_state_ptrs_per_layer[linear_idx],
                &mut bufs.recurrent.gdr_out_batch,
                c.linear_num_key_heads,
                c.linear_num_value_heads,
                c.linear_key_head_dim,
                c.linear_value_head_dim,
                batch_size,
            )?;
        }

        // 4. Batched gated RMSNorm
        ops::rms_norm_gated_batch_into(
            &self.ctx,
            &bufs.recurrent.gdr_out_batch,
            &attn.norm_weight,
            &bufs.recurrent.z_batch,
            &mut bufs.recurrent.normed_gated,
            c.linear_num_value_heads,
            c.linear_value_head_dim,
            eps,
        );

        // 5. Batched out projection
        ops::gemm_into(
            &self.ctx,
            &attn.out_proj,
            &bufs.recurrent.normed_gated,
            &mut bufs.common.attn_results,
        );

        // 6. Residual + post-attention norm + MLP
        self.decode_batch_mlp(layer, hidden, bufs, batch_size)?;

        Ok(())
    }

    /// Shared: residual add + post-attention norm + MLP + residual add.
    fn decode_batch_mlp(
        &self,
        layer: &TransformerBlock35,
        hidden: &mut HiddenStates,
        bufs: &mut BatchDecodeBuffers35,
        _batch_size: usize,
    ) -> Result<()> {
        let eps = self.config.rms_norm_eps;

        // Residual 1: hidden_mid = hidden + attn_results
        ops::add_batch_into(
            &self.ctx,
            hidden,
            &bufs.common.attn_results,
            &mut bufs.common.hidden_mid,
        )?;

        // Post-attention RMSNorm (offset variant)
        ops::rms_norm_batch_offset_into(
            &self.ctx,
            &bufs.common.hidden_mid,
            &layer.post_attention_layernorm,
            eps,
            &mut bufs.common.normed,
        )?;

        // MLP: gate + up → silu_mul → down
        ops::gemm_into(
            &self.ctx,
            &layer.mlp.gate_proj,
            &bufs.common.normed,
            &mut bufs.mlp.gate_out,
        );
        ops::gemm_into(
            &self.ctx,
            &layer.mlp.up_proj,
            &bufs.common.normed,
            &mut bufs.mlp.up_out,
        );
        ops::silu_mul_batch_into(
            &self.ctx,
            &bufs.mlp.gate_out,
            &bufs.mlp.up_out,
            &mut bufs.mlp.act_out,
        )?;
        ops::gemm_into(
            &self.ctx,
            &layer.mlp.down_proj,
            &bufs.mlp.act_out,
            &mut bufs.common.o_buf,
        );

        // Residual 2: hidden = hidden_mid + mlp_out
        ops::add_batch_into(
            &self.ctx,
            &bufs.common.hidden_mid,
            &bufs.common.o_buf,
            &mut bufs.common.hidden_out,
        )?;
        std::mem::swap(hidden, &mut bufs.common.hidden_out);

        Ok(())
    }
}
