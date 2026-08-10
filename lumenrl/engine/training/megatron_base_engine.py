# Copyright 2025 LumenRL Contributors
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.

"""Shared training logic for Megatron-Core engines.

The concrete native engine owns model construction, topology, and checkpoint
format. This base provides common forward, packed batching, log-prob, policy
loss, optimizer, scheduler, and data-parallel helpers.
"""

from __future__ import annotations

import logging
import os
from contextlib import nullcontext
from typing import Any

import torch
import torch.distributed as dist

from lumenrl.algorithms.loss_functions import (
    asymmetric_clip_loss,
    kl_penalty,
    policy_gradient_loss,
)
from lumenrl.core.protocol import DataProto
from lumenrl.core.types import AlgorithmName
from lumenrl.engine.training.base_engine import BaseEngine
from lumenrl.engine.training.qwen3_megatron_bridge import Qwen3Dims

logger = logging.getLogger(__name__)
logger.setLevel(os.getenv("LUMENRL_LOGGING_LEVEL", "INFO"))


def _response_mask_is_token_indexed(tensors: dict[str, torch.Tensor]) -> bool:
    """Whether response_mask uses token columns [S], rather than log-prob columns [S-1]."""
    response_mask = tensors.get("response_mask")
    input_ids = tensors.get("input_ids")
    return bool(
        response_mask is not None
        and input_ids is not None
        and response_mask.shape[-1] >= input_ids.shape[-1]
    )


class _FusedTokenLogProb(torch.autograd.Function):
    """Memory-efficient per-token log-prob: ``log p(target) = logit_target - logsumexp``.

    Retains a single ``[L, V]`` softmax buffer for backward instead of the
    several ``[L, V]`` tensors that ``log_softmax(logits).gather(...)`` keeps
    alive (the full log_softmax output plus its gradient). Values/gradients are
    exact. Backward uses ``grad_logits = (onehot(target) - softmax) * grad_lp``.
    """

    @staticmethod
    def forward(ctx, logits, target):
        logits = logits.float()
        m = logits.max(dim=-1, keepdim=True).values          # [L,1]
        shifted = logits.sub(m)                               # new [L,V]
        exp = shifted.exp_()                                  # in-place -> exp
        Z = exp.sum(dim=-1, keepdim=True)                     # [L,1]
        softmax = exp.div_(Z)                                 # in-place -> softmax
        logZ = Z.log_().add_(m)                               # logsumexp [L,1]
        tgt_logit = logits.gather(-1, target.unsqueeze(-1))   # [L,1]
        log_prob = (tgt_logit - logZ).squeeze(-1)             # [L]
        ctx.save_for_backward(softmax, target)
        return log_prob

    @staticmethod
    def backward(ctx, grad_lp):
        softmax, target = ctx.saved_tensors                   # softmax [L,V]
        grad = softmax.neg_()                                 # -softmax (reuse buffer)
        grad.scatter_add_(-1, target.unsqueeze(-1), torch.ones_like(grad[:, :1]))
        grad.mul_(grad_lp.unsqueeze(-1))
        return grad, None


class MegatronBaseEngine(BaseEngine):
    """Shared implementation for concrete Megatron-Core engines."""

    def __init__(self, model_config, engine_config, optimizer_config, model_name: str = ""):
        super().__init__()
        self.model_config = model_config if isinstance(model_config, dict) else vars(model_config)
        self.engine_config = engine_config if isinstance(engine_config, dict) else vars(engine_config)
        self.optimizer_config = (
            optimizer_config if isinstance(optimizer_config, dict) else vars(optimizer_config)
        )
        self.model_name = model_name or self.model_config.get("local_path", "")
        self.module: torch.nn.Module | None = None   # unwrapped GPTModel (eval fwd, save/load)
        self._ddp: Any = None                          # Megatron DistributedDataParallel wrapper
        self.optimizer: Any = None                     # Megatron distributed optimizer
        self.lr_scheduler: Any = None                  # Megatron OptimizerParamScheduler
        self._dims: Qwen3Dims | None = None
        self.mode: str | None = None

    # -- offload (Ray path: never offload) --
    @property
    def is_param_offload_enabled(self) -> bool:
        return False

    @property
    def is_optimizer_offload_enabled(self) -> bool:
        return False

    def train_mode(self, **kwargs):
        return nullcontext()

    def eval_mode(self, **kwargs):
        return nullcontext()

    # ------------------------------------------------------------------
    def _rank(self) -> int:
        return dist.get_rank() if dist.is_initialized() else 0

    def get_data_parallel_size(self) -> int:
        try:
            from megatron.core import parallel_state as mpu
            return mpu.get_data_parallel_world_size()
        except Exception:
            return dist.get_world_size() if dist.is_initialized() else 1

    def get_data_parallel_rank(self) -> int:
        try:
            from megatron.core import parallel_state as mpu
            return mpu.get_data_parallel_rank()
        except Exception:
            return self._rank()

    def get_data_parallel_group(self):
        try:
            from megatron.core import parallel_state as mpu
            return mpu.get_data_parallel_group()
        except Exception:
            return dist.group.WORLD if dist.is_initialized() else None

    def to(self, device: str, model: bool = True, optimizer: bool = True, grad: bool = True) -> None:
        return

    # ------------------------------------------------------------------
    def _forward_logits(self, ids: torch.Tensor, model=None) -> torch.Tensor:
        """Run the model on a single unpadded sequence -> logits [L, V] (float).

        ``model`` defaults to the unwrapped GPTModel (eval); pass ``self._ddp``
        during training so DDP grad hooks fire and grads land in the buffer.
        """
        m = model if model is not None else self.module
        L = ids.numel()
        inp = ids.view(1, L)
        pos = torch.arange(L, device=ids.device).view(1, L)
        out = m(input_ids=inp, position_ids=pos, attention_mask=None)
        logits = out.logits if hasattr(out, "logits") else out
        return logits.view(L, -1).float()

    def _forward_logits_packed(self, ids_list, model=None) -> tuple[torch.Tensor, list[int]]:
        """Packed varlen forward: concat ``ids_list`` (per-sequence 1D token tensors)
        into one [1,T] stream and run a single GPTModel forward with thd
        ``PackedSeqParams``. Returns ``(logits [T,V] float, offsets)`` where
        ``offsets[i]:offsets[i+1]`` slices sequence ``i``'s logits.

        Rotary is applied per-segment by Megatron's thd path (via cu_seqlens);
        attention is isolated per-segment by flash_attn_varlen. So each sequence's
        logits are identical to a standalone forward (up to bf16 nondeterminism)."""
        from megatron.core.packed_seq_params import PackedSeqParams
        m = model if model is not None else self.module
        lens = [int(t.numel()) for t in ids_list]
        offsets = [0]
        for L in lens:
            offsets.append(offsets[-1] + L)
        T = offsets[-1]
        tokens = torch.cat([t.view(-1) for t in ids_list], dim=0).view(1, T)
        # per-segment position ids (0..L_i-1); ignored by thd rotary but kept correct.
        pos = torch.cat([torch.arange(L, device=tokens.device) for L in lens], dim=0).view(1, T)
        cu = torch.tensor(offsets, dtype=torch.int32, device=tokens.device)
        max_seqlen = max(lens) if lens else 0
        pp = PackedSeqParams(
            cu_seqlens_q=cu, cu_seqlens_kv=cu,
            max_seqlen_q=max_seqlen, max_seqlen_kv=max_seqlen, qkv_format="thd",
        )
        out = m(input_ids=tokens, position_ids=pos, attention_mask=None, packed_seq_params=pp)
        logits = out.logits if hasattr(out, "logits") else out
        return logits.view(T, -1).float(), offsets

    def _build_bins(self, lengths: list[int], budget: int) -> list[list[int]]:
        """Greedy bin-packing of row indices into groups whose summed token length
        stays <= ``budget`` (a row longer than budget forms its own bin)."""
        if budget <= 0:
            budget = max(lengths) if lengths else 1
        order = sorted(range(len(lengths)), key=lambda i: -lengths[i])
        bins: list[list[int]] = []
        bin_tokens: list[int] = []
        for i in order:
            Li = lengths[i]
            placed = False
            for b in range(len(bins)):
                if bin_tokens[b] + Li <= budget:
                    bins[b].append(i)
                    bin_tokens[b] += Li
                    placed = True
                    break
            if not placed:
                bins.append([i])
                bin_tokens.append(Li)
        return bins

    @staticmethod
    def _real_block(mask_row: torch.Tensor) -> tuple[int, int]:
        idx = mask_row.nonzero(as_tuple=False).squeeze(-1)
        if idx.numel() == 0:
            return 0, 0
        return int(idx[0].item()), int(idx.numel())

    # ---- memory-efficient log-prob helpers ----
    def _token_logprob_train(self, logits: torch.Tensor, targets: torch.Tensor) -> torch.Tensor:
        """Per-token log-prob with grad. Uses the fused single-buffer CE (optionally
        chunked over the sequence) when ``log_probs_chunk_size>0``; otherwise the
        original ``log_softmax(...).gather(...)`` path (kept for the smoke config)."""
        cs = self._logprob_chunk_size
        if cs and cs > 0:
            outs = []
            for s in range(0, logits.shape[0], cs):
                outs.append(_FusedTokenLogProb.apply(logits[s:s + cs], targets[s:s + cs]))
            return torch.cat(outs, dim=0)
        lp = torch.log_softmax(logits, dim=-1)
        return lp.gather(-1, targets.view(-1, 1)).squeeze(-1)

    def _logprob_entropy_nograd(
        self, logits: torch.Tensor, targets: torch.Tensor, want_entropy: bool,
    ) -> tuple[torch.Tensor, torch.Tensor | None]:
        """No-grad per-token log-prob (+ optional entropy), chunked over the
        sequence to bound the ``[chunk, V]`` softmax memory."""
        cs = self._logprob_chunk_size if (self._logprob_chunk_size and self._logprob_chunk_size > 0) else logits.shape[0]
        cs = max(1, cs)
        lps, ents = [], []
        for s in range(0, logits.shape[0], cs):
            lg = logits[s:s + cs]
            lsm = torch.log_softmax(lg, dim=-1)
            lps.append(lsm.gather(-1, targets[s:s + cs].view(-1, 1)).squeeze(-1))
            if want_entropy:
                ents.append(-(lsm.exp() * lsm).sum(-1))
        lp = torch.cat(lps, dim=0)
        ent = torch.cat(ents, dim=0) if want_entropy else None
        return lp, ent

    def _row_policy_loss(
        self,
        t,
        r,
        start,
        token_lp,
        algo_name,
        cfg_fn,
        bnt,
        dp,
        loss_agg_mode,
        global_batch_size,
    ):
        """DAPO/PG loss + PPO-KL metrics for one sequence, given its (grad-carrying)
        per-token log-prob ``token_lp`` [1, Lm]. Returns ``(loss_tensor|None, stats|None)``.
        Shared by the packed and per-row training paths."""
        Lm = token_lp.shape[-1]
        dev = token_lp.device

        def _col(name, shift):
            x = t.get(name)
            if x is None:
                return None
            x = x[r].to(dev)
            s0 = start + (1 if shift else 0)
            return x[s0:].reshape(1, -1)

        old_lp = _col("old_log_probs", shift=False)
        if old_lp is None:
            return None, None
        # Trainer masks are normally width S-1 and already aligned to log-prob
        # columns. Preserve compatibility with token-indexed width-S masks.
        resp_mask = _col(
            "response_mask",
            shift=_response_mask_is_token_indexed(t),
        )
        adv_t = t.get("advantages")
        if adv_t is None:
            return None, None
        if adv_t.dim() == 1:
            adv = adv_t[r].to(dev).view(1, 1).expand(1, Lm).float()
        else:
            adv = adv_t[r].to(dev)[start:].reshape(1, -1).float()
        ris = _col("rollout_is_weights", shift=False)
        ref_lp0 = _col("ref_log_probs", shift=False)
        rlp0 = _col("rollout_log_probs", shift=False)

        cand = [token_lp, old_lp, adv]
        for v in (resp_mask, ris, ref_lp0, rlp0):
            if v is not None:
                cand.append(v)
        Le = min(v.shape[-1] for v in cand)
        token_lp = token_lp[..., :Le]
        old_lp = old_lp[..., :Le]
        adv = adv[..., :Le]
        mask = resp_mask[..., :Le].float() if resp_mask is not None else None
        ris = ris[..., :Le] if ris is not None else None
        ref_lp = ref_lp0[..., :Le] if ref_lp0 is not None else None
        rlp = rlp0[..., :Le] if rlp0 is not None else None

        if algo_name == AlgorithmName.DAPO.value:
            loss = asymmetric_clip_loss(
                token_lp, old_lp, adv,
                float(cfg_fn("clip_ratio_low", 0.2)), float(cfg_fn("clip_ratio_high", 0.28)),
                mask=mask, clip_ratio_c=float(cfg_fn("clip_ratio_c", 0.0)),
                batch_num_tokens=bnt, dp_size=dp, rollout_is_weights=ris,
            )
        elif algo_name == AlgorithmName.GRPO.value:
            loss = asymmetric_clip_loss(
                token_lp,
                old_lp,
                adv,
                float(cfg_fn("clip_ratio", 0.2)),
                float(cfg_fn("clip_ratio_high", 0.28)),
                mask=mask,
                batch_num_tokens=bnt,
                dp_size=dp,
                loss_agg_mode=loss_agg_mode,
                global_batch_size=global_batch_size,
            )
        else:
            loss = policy_gradient_loss(
                token_lp,
                old_lp,
                adv,
                float(cfg_fn("clip_ratio", 0.2)),
                mask=mask,
            )
        kl_c = float(cfg_fn("kl_coeff", 0.0))
        if kl_c > 0.0 and ref_lp is not None:
            loss = loss + kl_c * kl_penalty(token_lp, ref_lp, mask=mask)

        stats = {"loss": float(loss.detach()), "ppo_kl_sum": 0.0, "ppo_kl_tok": 0.0,
                 "rc_kl_sum": 0.0, "rc_kl_tok": 0.0}
        if mask is not None:
            with torch.no_grad():
                tok = float(mask.sum())
                stats["ppo_kl_sum"] = float(((old_lp - token_lp) * mask).sum())
                stats["ppo_kl_tok"] = tok
                if rlp is not None:
                    stats["rc_kl_sum"] = float(((rlp - token_lp) * mask).sum())
                    stats["rc_kl_tok"] = tok
        return loss, stats

    # ---- engine-level compute_log_probs (actor delegates here) ----
    def engine_compute_log_probs(self, batch: DataProto) -> DataProto:
        seqs = batch["input_ids"]
        B, S = seqs.shape
        am = batch.tensors.get("attention_mask")
        if am is None:
            am = torch.ones_like(seqs)
        want_ent = bool(batch.meta.get("calculate_entropy", False))
        temperature = float(batch.meta.get("temperature", 1.0) or 1.0)

        lp_out = torch.zeros(B, S, dtype=torch.float32)
        ent_out = torch.zeros(B, S, dtype=torch.float32) if want_ent else None
        self.module.eval()

        def _emit(r, start, L, seg_logits, ids_row):
            tok_lp, ent = self._logprob_entropy_nograd(seg_logits[:-1], ids_row[1:], want_ent)  # [L-1]
            lp_out[r, start:start + L - 1] = tok_lp.cpu()
            if want_ent and ent is not None:
                ent_out[r, start:start + L - 1] = ent.cpu()

        with torch.no_grad():
            rows = []
            for r in range(B):
                start, L = self._real_block(am[r])
                if L >= 2:
                    rows.append((r, start, L))
            if self._dynamic_batch:
                budget = self._max_tokens_per_gpu if self._max_tokens_per_gpu > 0 else 21504
                lengths = [L for (_, _, L) in rows]
                for bin_rows in self._build_bins(lengths, budget):
                    ids_list = [seqs[rows[j][0], rows[j][1]:rows[j][1] + rows[j][2]].to("cuda") for j in bin_rows]
                    logits_packed, offsets = self._forward_logits_packed(ids_list, model=self.module)
                    logits_packed = logits_packed / temperature
                    for k, j in enumerate(bin_rows):
                        r, start, L = rows[j]
                        _emit(r, start, L, logits_packed[offsets[k]:offsets[k + 1]], ids_list[k])
            else:
                for (r, start, L) in rows:
                    ids = seqs[r, start:start + L].to("cuda")
                    logits = self._forward_logits(ids) / temperature  # [L,V]
                    _emit(r, start, L, logits, ids)
        tensors = {"log_probs": lp_out, "input_ids": batch["input_ids"]}
        if want_ent:
            tensors["entropy"] = ent_out
        return DataProto(tensors=tensors, meta=dict(batch.meta))

    # ---- engine-level DAPO/GRPO/SFT update (actor delegates here) ----
    def engine_update_policy(self, batch: DataProto) -> dict[str, float]:
        if batch.batch_size == 0:
            return {"loss": 0.0, "lr": self._cur_lr(), "grad_norm": 0.0}
        meta = dict(batch.meta)
        if meta.get("task_type") == "sft":
            return self._engine_update_sft(batch)
        algo_name = str(meta.get("algorithm", "dapo")).lower()
        temperature = float(meta.get("temperature", 1.0) or 1.0)
        bnt = meta.get("batch_num_tokens")
        dp = int(meta.get("dp_size", self.get_data_parallel_size()) or 1)
        algo_cfg_full = meta.get("algo_config", {}) or {}
        _sub = algo_cfg_full.get(algo_name)
        _sub = _sub if isinstance(_sub, dict) else {}

        def _cfg(key, default):
            v = _sub.get(key, algo_cfg_full.get(key, default))
            return default if v is None else v

        t = batch.tensors
        seqs = t["input_ids"]
        am = t.get("attention_mask")
        if am is None:
            am = torch.ones_like(seqs)
        B, S = seqs.shape
        loss_agg_mode = str(_cfg("loss_agg_mode", "token-mean"))
        global_batch_size = int(meta.get("global_batch_size") or B * dp)

        self.module.train()
        self._ddp.zero_grad_buffer()
        self.optimizer.zero_grad()

        loss_accum = 0.0
        ppo_kl_sum = 0.0
        ppo_kl_tok = 0.0
        rc_kl_sum = 0.0
        rc_kl_tok = 0.0
        n_rows = 0

        def _accum(stats):
            nonlocal loss_accum, ppo_kl_sum, ppo_kl_tok, rc_kl_sum, rc_kl_tok, n_rows
            loss_accum += stats["loss"]
            n_rows += 1
            ppo_kl_sum += stats["ppo_kl_sum"]
            ppo_kl_tok += stats["ppo_kl_tok"]
            rc_kl_sum += stats["rc_kl_sum"]
            rc_kl_tok += stats["rc_kl_tok"]

        # Collect valid (non-empty) rows.
        rows = []
        for r in range(B):
            start, L = self._real_block(am[r])
            if L >= 2:
                rows.append((r, start, L))

        if self._dynamic_batch:
            # ---- dynamic-batch packing: concat rows into varlen forwards ----
            budget = self._max_tokens_per_gpu if self._max_tokens_per_gpu > 0 else 21504
            lengths = [L for (_, _, L) in rows]
            for bin_rows in self._build_bins(lengths, budget):
                ids_list = [seqs[rows[j][0], rows[j][1]:rows[j][1] + rows[j][2]].to("cuda") for j in bin_rows]
                logits_packed, offsets = self._forward_logits_packed(ids_list, model=self._ddp)
                logits_packed = logits_packed / temperature  # [T,V] (grad)
                bin_loss = None
                for k, j in enumerate(bin_rows):
                    r, start, _L = rows[j]
                    seg = logits_packed[offsets[k]:offsets[k + 1]]           # [L,V]
                    token_lp = self._token_logprob_train(seg[:-1], ids_list[k][1:]).view(1, -1)
                    loss, stats = self._row_policy_loss(
                        t, r, start, token_lp, algo_name, _cfg, bnt, dp,
                        loss_agg_mode, global_batch_size,
                    )
                    if loss is None:
                        continue
                    bin_loss = loss if bin_loss is None else bin_loss + loss
                    _accum(stats)
                if bin_loss is not None:
                    bin_loss.backward()
        else:
            # ---- per-sequence forward (original path) ----
            for (r, start, L) in rows:
                ids = seqs[r, start:start + L].to("cuda")
                logits = self._forward_logits(ids, model=self._ddp) / temperature  # [L,V] (grad)
                token_lp = self._token_logprob_train(logits[:-1], ids[1:]).view(1, -1)  # [1,L-1]
                loss, stats = self._row_policy_loss(
                    t, r, start, token_lp, algo_name, _cfg, bnt, dp,
                    loss_agg_mode, global_batch_size,
                )
                if loss is None:
                    continue
                loss.backward()
                _accum(stats)

        grad_norm = self._optimizer_step()
        lr = self._sched_step()
        metrics = {
            "loss": (
                loss_accum
                if algo_name == AlgorithmName.GRPO.value
                else loss_accum / max(1, n_rows)
            ),
            "lr": lr,
            "grad_norm": grad_norm,
        }
        if ppo_kl_tok > 0:
            metrics["ppo_kl_sum"] = ppo_kl_sum
            metrics["ppo_kl_tok"] = ppo_kl_tok
        if rc_kl_tok > 0:
            metrics["rollout_corr_kl_sum"] = rc_kl_sum
            metrics["rollout_corr_kl_tok"] = rc_kl_tok
        return metrics

    def _engine_update_sft(self, batch: DataProto) -> dict[str, float]:
        """SFT training update: forward → log_probs → NLL → backward.

        Uses global token-mean normalization with cross-DP all-reduce,
        matching the FSDP2 path's ``sft_loss()`` behavior.
        """
        meta = dict(batch.meta)
        t = batch.tensors
        seqs = t["input_ids"]
        am = t.get("attention_mask")
        if am is None:
            am = torch.ones_like(seqs)
        loss_masks = t["loss_mask"]
        B, S = seqs.shape
        dp = int(meta.get("dp_size", self.get_data_parallel_size()) or 1)

        self.module.train()
        self._ddp.zero_grad_buffer()
        self.optimizer.zero_grad()

        rows = []
        for r in range(B):
            start, L = self._real_block(am[r])
            if L >= 2:
                rows.append((r, start, L))

        # Global token count for token-mean normalization (cross-DP all-reduce).
        local_tokens = sum(
            float(loss_masks[r, start + 1:start + L].sum()) for r, start, L in rows
        )
        num_tokens_t = torch.tensor(local_tokens, device="cuda")
        dp_group = self.get_data_parallel_group()
        if dp_group is not None and dist.is_initialized():
            dist.all_reduce(num_tokens_t, group=dp_group)
        global_num_tokens = max(int(num_tokens_t.item()), 1)

        loss_accum = 0.0
        token_accum = local_tokens

        for r, start, L in rows:
            ids = seqs[r, start:start + L].to("cuda")
            logits = self._forward_logits(ids, model=self._ddp)
            token_lp = self._token_logprob_train(logits[:-1], ids[1:])

            mask = loss_masks[r, start + 1:start + L].to(token_lp.device).float()
            Le = min(token_lp.shape[0], mask.shape[0])
            token_lp = token_lp[:Le]
            mask = mask[:Le]

            if mask.sum() < 1:
                del logits, token_lp
                continue
            loss = -(token_lp * mask).sum() / global_num_tokens * dp
            loss.backward()

            loss_accum += float(-(token_lp.detach() * mask).sum())
            del logits, token_lp, loss

        torch.cuda.empty_cache()
        grad_norm = self._optimizer_step()
        lr = self._sched_step()
        avg_loss = loss_accum / max(token_accum, 1)
        return {
            "loss": avg_loss,
            "sft_loss": avg_loss,
            "num_tokens": token_accum,
            "lr": lr,
            "grad_norm": grad_norm,
        }

    def _optimizer_step(self) -> float:
        """Reduce grads across DP (+reduce-scatter for the distributed optimizer),
        then step the Megatron distributed optimizer."""
        from megatron.core.distributed import finalize_model_grads
        finalize_model_grads([self._ddp])
        update_successful, grad_norm, _num_zeros = self.optimizer.step()
        if not update_successful:
            logger.warning("optimizer.step reported update_successful=False")
        return float(grad_norm) if grad_norm is not None else 0.0

    def _cur_lr(self) -> float:
        try:
            return float(self.optimizer.param_groups[0]["lr"])
        except Exception:
            return 0.0

    def _sched_step(self) -> float:
        if self.lr_scheduler is not None:
            self.lr_scheduler.step(increment=1)
        return self._cur_lr()

    def lr_scheduler_step(self) -> float:
        return self._cur_lr()
