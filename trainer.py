"""
trainer.py — Training Loop (Multi-GPU DDP Optimized)
======================================================
Key upgrades over the original:
  - True DistributedDataParallel (DDP) via torchrun — auto-detects 1–N GPUs
  - DistributedSampler so each GPU sees a unique shard (no wasted work)
  - Gradient accumulation (accum_steps) — lets effective batch = batch_size × accum × n_gpus
  - CUDA streams + non_blocking transfers to overlap CPU↔GPU data movement
  - Prefetch DataLoader with persistent_workers + prefetch_factor
  - torch.compile() on PyTorch ≥ 2.0 for ~20-30% extra throughput
  - Separate per-rank logging (only rank-0 writes to disk / TensorBoard)
  - Checkpoint save/load correctly handles DDP .module unwrapping
  - All original loss, AMP, and scheduling logic preserved
"""

import os
import json
import time
import logging
import math
from pathlib import Path
from typing import Optional

import torch
import torch.nn as nn
import torch.distributed as dist
from torch.nn.parallel import DistributedDataParallel as DDP
from torch.utils.data.distributed import DistributedSampler
from torch.optim import AdamW
from torch.optim.lr_scheduler import CosineAnnealingLR, LinearLR, SequentialLR
from torch.amp import GradScaler, autocast

from model import MimiHuBERTBridge, FeatureDiscriminator
from losses import BridgeLoss
from dataset import build_dataloaders, MimiHuBERTDataset, collate_fn
from torch.utils.data import DataLoader

logger = logging.getLogger(__name__)


# ─────────────────────────────────────────────────────────────────────────────
# DDP helpers
# ─────────────────────────────────────────────────────────────────────────────

def setup_ddp() -> tuple[int, int, int]:
    """
    Initialise the NCCL process group when launched with torchrun.
    Returns (local_rank, global_rank, world_size).
    Falls back gracefully to single-GPU when not launched via torchrun.
    """
    local_rank  = int(os.environ.get("LOCAL_RANK",  0))
    global_rank = int(os.environ.get("RANK",        0))
    world_size  = int(os.environ.get("WORLD_SIZE",  1))

    if world_size > 1 and not dist.is_initialized():
        dist.init_process_group(backend="nccl")
        torch.cuda.set_device(local_rank)

    return local_rank, global_rank, world_size


def teardown_ddp():
    if dist.is_initialized():
        dist.destroy_process_group()


def _unwrap(model: nn.Module) -> nn.Module:
    """Strip DDP / DataParallel wrapper to get the raw module."""
    if isinstance(model, (DDP, nn.DataParallel)):
        return model.module
    return model


def _is_main(global_rank: int) -> bool:
    return global_rank == 0


# ─────────────────────────────────────────────────────────────────────────────
# Metrics
# ─────────────────────────────────────────────────────────────────────────────

def compute_pitch_correlation(pred_f0, gt_f0, voiced) -> float:
    if voiced.sum() < 2:
        return 0.0
    p = pred_f0[voiced].float()
    g = gt_f0[voiced].float()
    if p.std() < 1e-8 or g.std() < 1e-8:
        return 0.0
    return torch.corrcoef(torch.stack([p, g]))[0, 1].item()


# ─────────────────────────────────────────────────────────────────────────────
# LR Scheduler
# ─────────────────────────────────────────────────────────────────────────────

def build_scheduler(optimizer, cfg: dict, steps_per_epoch: int):
    t       = cfg["training"]
    warmup  = t["warmup_steps"]
    total   = t["num_epochs"] * steps_per_epoch
    warmup_sched = LinearLR(optimizer, start_factor=1e-4, end_factor=1.0, total_iters=warmup)
    cosine_sched = CosineAnnealingLR(optimizer, T_max=max(1, total - warmup), eta_min=1e-6)
    return SequentialLR(optimizer, schedulers=[warmup_sched, cosine_sched], milestones=[warmup])


# ─────────────────────────────────────────────────────────────────────────────
# Prefetch wrapper — overlaps CPU→GPU transfer with GPU compute
# ─────────────────────────────────────────────────────────────────────────────

class CUDAPrefetcher:
    """
    Wraps a DataLoader and eagerly transfers the next batch to GPU using a
    dedicated CUDA stream while the current batch is being processed.
    This eliminates the CPU↔GPU synchronization stall on every iteration.
    """
    def __init__(self, loader, device: torch.device):
        self.loader = loader
        self.device = device
        self.stream = torch.cuda.Stream() if device.type == "cuda" else None
        # _iter must exist before _preload() is called
        self._iter = iter(self.loader)
        self._preload()

    def _preload(self):
        try:
            self._next = next(self._iter)
        except StopIteration:
            self._next = None
            return
        if self.stream is None:
            return
        with torch.cuda.stream(self.stream):
            self._next = {
                k: v.to(self.device, non_blocking=True) if isinstance(v, torch.Tensor) else v
                for k, v in self._next.items()
            }

    def __iter__(self):
        # Reset iterator and prefetch the first batch for each new epoch
        self._iter = iter(self.loader)
        self._preload()
        return self

    def __next__(self):
        if self.stream is not None:
            torch.cuda.current_stream().wait_stream(self.stream)
        batch = self._next
        if batch is None:
            raise StopIteration
        self._preload()
        return batch

    def __len__(self):
        return len(self.loader)


# ─────────────────────────────────────────────────────────────────────────────
# Trainer
# ─────────────────────────────────────────────────────────────────────────────

class Trainer:

    def __init__(self, cfg: dict):
        self.cfg = cfg
        t_cfg = cfg["training"]

        # ── DDP setup ─────────────────────────────────────────────────────────
        self.local_rank, self.global_rank, self.world_size = setup_ddp()
        self.is_main = _is_main(self.global_rank)

        # ── Device ────────────────────────────────────────────────────────────
        if torch.cuda.is_available():
            self.device = torch.device(f"cuda:{self.local_rank}")
        else:
            self.device = torch.device("cpu")

        self.amp_device      = self.device.type
        self.mixed_precision = t_cfg.get("mixed_precision", True) and self.device.type == "cuda"

        torch.manual_seed(t_cfg.get("seed", 42) + self.global_rank)

        if self.is_main:
            logger.info(
                f"World size: {self.world_size} GPU(s) | "
                f"Device: {self.device} | AMP: {self.mixed_precision}"
            )
            if self.device.type == "cuda":
                for i in range(torch.cuda.device_count()):
                    logger.info(f"  GPU {i}: {torch.cuda.get_device_name(i)}")

        # ── Gradient accumulation ─────────────────────────────────────────────
        # With 4×RTX 4090 + batch_size=16 per GPU → effective batch = 64 samples
        # If you want a larger logical batch, set accum_steps > 1 in config.
        self.accum_steps = int(t_cfg.get("accum_steps", 1))
        if self.is_main:
            eff_batch = t_cfg["batch_size"] * self.world_size * self.accum_steps
            logger.info(
                f"Batch: {t_cfg['batch_size']} per GPU × {self.world_size} GPUs "
                f"× {self.accum_steps} accum = {eff_batch} effective"
            )

        # ── Build models ──────────────────────────────────────────────────────
        bridge_raw = MimiHuBERTBridge(cfg).to(self.device)
        disc_raw   = FeatureDiscriminator(
            input_dim  = cfg["model"]["output_dim"],
            hidden     = t_cfg["disc_hidden"],
            num_layers = t_cfg["disc_layers"],
        ).to(self.device)

        # torch.compile is intentionally disabled:
        #   1. This model returns (tensor, None) — the None output causes
        #      AOT Autograd to crash regardless of suppress_errors mode.
        #   2. Variable-length padded batches produce a different tensor stride
        #      every step, exhausting the recompile cache (limit=8) immediately
        #      and falling back to eager anyway — costing ~10 min of wasted
        #      compilation with zero throughput benefit.
        # DDP + AMP + CUDAPrefetcher already achieves full GPU utilisation.

        # ── DDP wrap ──────────────────────────────────────────────────────────
        if self.world_size > 1:
            self.bridge = DDP(
                bridge_raw, device_ids=[self.local_rank],
                output_device=self.local_rank,
                find_unused_parameters=False,  # faster when all params used
            )
            self.disc = DDP(
                disc_raw, device_ids=[self.local_rank],
                output_device=self.local_rank,
                find_unused_parameters=False,
            )
        else:
            self.bridge = bridge_raw
            self.disc   = disc_raw

        # ── Loss (not wrapped — lives on primary device) ──────────────────────
        self.criterion = BridgeLoss(cfg).to(self.device)

        # ── Optimizers ────────────────────────────────────────────────────────
        self.opt_g = AdamW(
            list(_unwrap(self.bridge).parameters()) + list(self.criterion.parameters()),
            lr           = t_cfg["learning_rate"],
            weight_decay = t_cfg["weight_decay"],
            fused        = (self.device.type == "cuda"),   # fused AdamW: ~10% faster
        )
        self.opt_d = AdamW(
            _unwrap(self.disc).parameters(),
            lr           = t_cfg["disc_lr"],
            weight_decay = t_cfg["weight_decay"],
            fused        = (self.device.type == "cuda"),
        )

        # ── Data — each rank gets its own shard via DistributedSampler ────────
        self.train_loader, self.val_loader = self._build_distributed_loaders(cfg)
        steps_per_epoch = len(self.train_loader) // self.accum_steps

        # ── Schedulers ────────────────────────────────────────────────────────
        self.sched_g = build_scheduler(self.opt_g, cfg, steps_per_epoch)
        self.sched_d = CosineAnnealingLR(
            self.opt_d,
            T_max  = t_cfg["num_epochs"] * steps_per_epoch,
            eta_min= 1e-7,
        )

        # ── AMP GradScalers ───────────────────────────────────────────────────
        self.scaler_g = GradScaler(device=self.amp_device, enabled=self.mixed_precision)
        self.scaler_d = GradScaler(device=self.amp_device, enabled=self.mixed_precision)

        # ── State ─────────────────────────────────────────────────────────────
        self.global_step  = 0
        self.epoch        = 0
        self.best_val_mse = math.inf

        self.ckpt_dir = Path(cfg["paths"]["checkpoint_dir"])
        self.log_dir  = Path(cfg["paths"]["log_dir"])
        if self.is_main:
            self.ckpt_dir.mkdir(parents=True, exist_ok=True)
            self.log_dir.mkdir(parents=True, exist_ok=True)

        # ── TensorBoard (main rank only) ──────────────────────────────────────
        self.writer = None
        if self.is_main and cfg["paths"].get("tensorboard", True):
            try:
                from torch.utils.tensorboard import SummaryWriter
                self.writer = SummaryWriter(log_dir=str(self.log_dir))
                logger.info(f"TensorBoard → {self.log_dir}")
            except ImportError:
                logger.warning("tensorboard not installed; skipping.")

        self.disc_start_step = t_cfg.get("disc_start_step", 5000)

        if self.is_main:
            p = _unwrap(self.bridge).get_param_count()
            logger.info(
                f"Bridge parameters: {p['trainable']:,} trainable / {p['total']:,} total"
            )

    # ─────────────────────────────────────────────────────────────────────────
    # DataLoader construction with DistributedSampler + prefetch tuning
    # ─────────────────────────────────────────────────────────────────────────

    def _build_distributed_loaders(self, cfg: dict):
        d_cfg = cfg["data"]
        t_cfg = cfg["training"]

        train_ds = MimiHuBERTDataset(d_cfg["train_manifest"], cfg, "train", "cpu")
        val_ds   = MimiHuBERTDataset(d_cfg["val_manifest"],   cfg, "val",   "cpu")

        # DistributedSampler shards the dataset across GPUs with no overlap
        train_sampler = (
            DistributedSampler(train_ds, num_replicas=self.world_size,
                               rank=self.global_rank, shuffle=True, drop_last=True)
            if self.world_size > 1 else None
        )
        val_sampler = (
            DistributedSampler(val_ds, num_replicas=self.world_size,
                               rank=self.global_rank, shuffle=False, drop_last=False)
            if self.world_size > 1 else None
        )

        # num_workers: each GPU rank gets its own pool of workers.
        # 4 workers per GPU is a solid default; DataLoader clamps to CPU count.
        num_workers = d_cfg.get("num_workers", 4)

        train_loader = DataLoader(
            train_ds,
            batch_size      = t_cfg["batch_size"],
            sampler         = train_sampler,
            shuffle         = (train_sampler is None),   # shuffle only when no sampler
            num_workers     = num_workers,
            collate_fn      = collate_fn,
            pin_memory      = True,
            drop_last       = True,
            persistent_workers = True,   # workers stay alive between epochs
            prefetch_factor = 4,         # pre-load 4 batches per worker
        )
        val_loader = DataLoader(
            val_ds,
            batch_size      = t_cfg["batch_size"],
            sampler         = val_sampler,
            shuffle         = False,
            num_workers     = max(num_workers // 2, 2),
            collate_fn      = collate_fn,
            pin_memory      = True,
            drop_last       = False,
            persistent_workers = True,
            prefetch_factor = 2,
        )

        self.train_sampler = train_sampler
        return train_loader, val_loader

    # ─────────────────────────────────────────────────────────────────────────

    def _to_device(self, batch: dict) -> dict:
        return {
            k: v.to(self.device, non_blocking=True) if isinstance(v, torch.Tensor) else v
            for k, v in batch.items()
        }

    # ─────────────────────────────────────────────────────────────────────────
    # Train step — supports gradient accumulation
    # ─────────────────────────────────────────────────────────────────────────

    def _train_step(self, batch: dict, is_accum_step: bool) -> dict:
        """
        is_accum_step=True  → accumulate gradients, do NOT call optimizer.step()
        is_accum_step=False → final micro-step: step + zero_grad
        """
        tokens  = batch["tokens"]
        target  = batch["hubert"]
        use_adv = self.global_step >= self.disc_start_step

        # ── Discriminator step ────────────────────────────────────────────────
        d_logs = {}
        if use_adv and not is_accum_step:
            self.opt_d.zero_grad(set_to_none=True)
            with autocast(device_type=self.amp_device, enabled=self.mixed_precision):
                hs_det, _ = self.bridge(tokens)
                pred_det = hs_det.last_hidden_state   # (B, T, 768)
                real_logits = self.disc(target)
                fake_logits = self.disc(pred_det.detach())
                d_loss, d_logs = self.criterion.adv.discriminator_loss(real_logits, fake_logits)

            self.scaler_d.scale(d_loss).backward()
            self.scaler_d.unscale_(self.opt_d)
            torch.nn.utils.clip_grad_norm_(
                _unwrap(self.disc).parameters(), self.cfg["training"]["grad_clip"]
            )
            self.scaler_d.step(self.opt_d)
            self.scaler_d.update()
            self.sched_d.step()

        # ── Generator step ────────────────────────────────────────────────────
        # When using DDP + gradient accumulation, use no_sync() on accumulation
        # micro-steps so gradients aren't reduced until the final step.
        ctx = (
            self.bridge.no_sync()                    # suppress all-reduce
            if (self.world_size > 1 and is_accum_step and isinstance(self.bridge, DDP))
            else _null_ctx()
        )

        scale = 1.0 / self.accum_steps   # normalize loss for accumulation
        with ctx:
            with autocast(device_type=self.amp_device, enabled=self.mixed_precision):
                hs, _           = self.bridge(tokens)
                pred            = hs.last_hidden_state   # (B, T, 768) — train vs teacher
                fake_disc_logits = self.disc(pred) if use_adv else None
                g_loss, g_logs  = self.criterion(pred, target, batch, fake_disc_logits)
                g_loss          = g_loss * scale

            self.scaler_g.scale(g_loss).backward()

        if not is_accum_step:
            self.scaler_g.unscale_(self.opt_g)
            torch.nn.utils.clip_grad_norm_(
                list(_unwrap(self.bridge).parameters()) + list(self.criterion.parameters()),
                self.cfg["training"]["grad_clip"],
            )
            self.scaler_g.step(self.opt_g)
            self.scaler_g.update()
            self.opt_g.zero_grad(set_to_none=True)
            self.sched_g.step()

        return {**g_logs, **d_logs}

    # ─────────────────────────────────────────────────────────────────────────
    @torch.no_grad()
    def _val_epoch(self) -> dict:
        self.bridge.eval()
        agg = {}
        n   = 0

        for batch in self.val_loader:
            batch = self._to_device(batch)
            with autocast(device_type=self.amp_device, enabled=self.mixed_precision):
                hs, _ = self.bridge(batch["tokens"])
                pred  = hs.last_hidden_state   # (B, T, 768)

            pred_fp32   = pred.float()
            target_fp32 = batch["hubert"].float()
            _, logs     = self.criterion(pred_fp32, target_fp32, batch)

            if batch.get("f0") is not None:
                f0_pred = self.criterion.prosody.f0_head(pred_fp32).squeeze(-1)
                pc = compute_pitch_correlation(
                    f0_pred.cpu().flatten(),
                    batch["f0"].cpu().flatten(),
                    batch["voiced_mask"].cpu().flatten(),
                )
                logs["pitch_corr"] = pc

            for k, v in logs.items():
                agg[k] = agg.get(k, 0.0) + (v if isinstance(v, float) else float(v))
            n += 1

        # Average across local batches, then across all ranks
        agg = {k: v / max(n, 1) for k, v in agg.items()}
        if self.world_size > 1:
            for k in agg:
                t = torch.tensor(agg[k], device=self.device)
                dist.all_reduce(t, op=dist.ReduceOp.AVG)
                agg[k] = t.item()

        self.bridge.train()
        return agg

    # ─────────────────────────────────────────────────────────────────────────

    def _log(self, logs: dict, prefix: str = "train"):
        if self.is_main and self.writer:
            for k, v in logs.items():
                self.writer.add_scalar(f"{prefix}/{k}", v, self.global_step)

    # ─────────────────────────────────────────────────────────────────────────

    def save_checkpoint(self, tag: str, val_logs: Optional[dict] = None):
        if not self.is_main:
            return
        ckpt = {
            "step":    self.global_step,
            "epoch":   self.epoch,
            "bridge":  _unwrap(self.bridge).state_dict(),
            "disc":    _unwrap(self.disc).state_dict(),
            "opt_g":   self.opt_g.state_dict(),
            "opt_d":   self.opt_d.state_dict(),
            "sched_g": self.sched_g.state_dict(),
            "sched_d": self.sched_d.state_dict(),
            "best_val":self.best_val_mse,
            "val_logs":val_logs or {},
        }
        path = self.ckpt_dir / f"bridge_{tag}.pt"
        torch.save(ckpt, path)
        logger.info(f"Saved checkpoint → {path}")

    def load_checkpoint(self, path: str):
        # weights_only=False needed because checkpoints contain optimizer states
        # (non-tensor Python objects). map_location ensures each rank loads to
        # its own device rather than all piling onto cuda:0.
        ckpt = torch.load(path, map_location=self.device, weights_only=False)
        _unwrap(self.bridge).load_state_dict(ckpt["bridge"])
        _unwrap(self.disc).load_state_dict(ckpt["disc"])
        self.opt_g.load_state_dict(ckpt["opt_g"])
        self.opt_d.load_state_dict(ckpt["opt_d"])
        self.sched_g.load_state_dict(ckpt["sched_g"])
        self.sched_d.load_state_dict(ckpt["sched_d"])
        self.global_step  = ckpt["step"]
        self.epoch        = ckpt["epoch"]
        self.best_val_mse = ckpt.get("best_val", math.inf)
        logger.info(f"Resumed from step {self.global_step} (epoch {self.epoch})")

    # ─────────────────────────────────────────────────────────────────────────
    def train(self, resume_from: Optional[str] = None):
        if resume_from:
            self.load_checkpoint(resume_from)

        t_cfg      = self.cfg["training"]
        num_epochs = t_cfg["num_epochs"]

        if self.is_main:
            logger.info(f"Starting training — {num_epochs} epochs")

        self.bridge.train()
        prefetcher = CUDAPrefetcher(self.train_loader, self.device)

        for epoch in range(self.epoch, num_epochs):
            self.epoch = epoch

            # Tell the sampler which epoch we're on so shuffle is deterministic
            if self.world_size > 1 and self.train_sampler is not None:
                self.train_sampler.set_epoch(epoch)

            t0          = time.time()
            epoch_logs  = {}
            n_steps     = 0
            micro_step  = 0

            for batch in prefetcher:
                micro_step  += 1
                is_accum     = (micro_step % self.accum_steps != 0)
                step_logs    = self._train_step(batch, is_accum_step=is_accum)

                if not is_accum:
                    for k, v in step_logs.items():
                        epoch_logs[k] = epoch_logs.get(k, 0.0) + v
                    n_steps          += 1
                    self.global_step += 1

                    if self.is_main and self.global_step % 100 == 0:
                        avg = {k: v / n_steps for k, v in epoch_logs.items()}
                        lr  = self.opt_g.param_groups[0]["lr"]
                        total_v = avg.get('total', float('nan'))
                        total_s = f"{total_v:.4f}" if total_v == total_v else "nan"
                        logger.info(
                            f"Step {self.global_step:6d} | epoch {epoch+1}/{num_epochs} | "
                            f"loss={total_s} | lr={lr:.2e} | "
                            f"elapsed={time.time()-t0:.0f}s"
                        )
                        self._log(step_logs, "train")

            # ── Validation ────────────────────────────────────────────────────
            val_logs = self._val_epoch()
            if self.is_main:
                self._log(val_logs, "val")
                val_mse = val_logs.get("recon_mse", math.inf)
                # Build readable log line; skip nan values gracefully
                parts = []
                for k, v in val_logs.items():
                    if k == "recon_mse":
                        continue
                    if v != v:   # nan check
                        parts.append(f"{k}=nan")
                    else:
                        parts.append(f"{k}={v:.4f}")
                logger.info(
                    f"[Epoch {epoch+1:3d}] val_mse={val_mse:.5f} | " + " | ".join(parts)
                )

                # ── Checkpointing ─────────────────────────────────────────────
                self.save_checkpoint(f"epoch{epoch+1:03d}", val_logs)
                if val_mse < self.best_val_mse:
                    self.best_val_mse = val_mse
                    self.save_checkpoint("best", val_logs)
                    logger.info(f"  ↳ New best val MSE: {val_mse:.5f}")

            # Sync all ranks before next epoch
            if self.world_size > 1:
                dist.barrier()

        if self.is_main and self.writer:
            self.writer.close()
        teardown_ddp()
        if self.is_main:
            logger.info("Training complete.")


# ─────────────────────────────────────────────────────────────────────────────
# Null context manager (stand-in when no_sync() is not needed)
# ─────────────────────────────────────────────────────────────────────────────

from contextlib import contextmanager

@contextmanager
def _null_ctx():
    yield