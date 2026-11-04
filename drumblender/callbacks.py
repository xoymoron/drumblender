import subprocess
import json
import os
from functools import partial
from functools import reduce
from datetime import datetime
from datetime import timezone
from pathlib import Path
from types import MethodType
from typing import Any
from typing import Literal

import pytorch_lightning as pl
import torch
import torchaudio
from pytorch_lightning.callbacks import Callback
from pytorch_lightning.callbacks import ModelCheckpoint
from pytorch_lightning.cli import SaveConfigCallback
from pytorch_lightning.loggers import TensorBoardLogger
from pytorch_lightning.loggers import WandbLogger
from wandb import Audio


class LogAudioCallback(Callback):
    """Log audio samples to Weights & Biases."""

    model: pl.LightningModule
    stored_forward: MethodType

    def __init__(
        self,
        on_train: bool,
        on_val: bool,
        on_test: bool,
        save_audio_sr: int = 48000,
        n_batches: int = 1,
        log_on_epoch_end: bool = True,
        max_audio_samples: int = 8,  # Limit the number of samples logged to W&B
        train_log_every_n_steps: int = 2000,
        val_log_every_n_steps: int = 2000,
    ):
        # ### HIGHLIGHT: Keep legacy constructor compatibility; cadence args are intentionally ignored.
        _ = log_on_epoch_end
        _ = train_log_every_n_steps
        _ = val_log_every_n_steps

        self.on_train = on_train
        self.on_val = on_val
        self.on_test = on_test

        self.save_audio_sr = save_audio_sr
        self.n_batches = n_batches

        self.saved_targets: dict[str, list[Any]] = dict(train=[], val=[], test=[])
        self.saved_reconstructions: dict[str, list[Any]] = dict(
            train=[], val=[], test=[]
        )

        # ### HIGHLIGHT: Force epoch-only audio logging for stable and predictable cadence.
        self.log_on_epoch_end = True
        self.max_audio_samples = max_audio_samples

        # ### HIGHLIGHT: Rotate validation audio source batch across validation runs.
        self._val_round = 0
        self._val_target_batch_idx = 0
        # ### HIGHLIGHT: Log validation audio once per training epoch.
        self._log_val_this_round = True
        self._last_logged_val_audio_epoch = -1
        self._capturing_train_batch = False

    # Store a local reference to the model on setup
    def setup(
        self, trainer: pl.Trainer, pl_module: pl.LightningModule, stage: str
    ) -> None:
        self.model = pl_module

    def _wrap_forward(self, split: str) -> None:
        self.stored_forward = self.model.forward

        # Wrap the model's forward method to save the audio
        def wrapped_forward(self, *args, callback=None, split=None, **kwargs):
            output = callback.stored_forward(*args, **kwargs)
            callback._save_batch(output, split, "reconstruction")
            return output

        wrapped_forward = partial(
            MethodType(wrapped_forward, self.model),
            callback=self,
            split=split,
        )

        self.model.forward = wrapped_forward  # type: ignore

    def _unwrap_forward(self) -> None:
        self.model.forward = self.stored_forward  # type: ignore

    def on_train_batch_start(
        self,
        trainer: pl.Trainer,
        pl_module: pl.LightningModule,
        batch: Any,
        batch_idx: int,
    ) -> None:
        # ### HIGHLIGHT: Avoid forward monkey-patching on non-zero DDP ranks.
        if not trainer.is_global_zero:
            return

        if not self.on_train:
            return

        should_capture = batch_idx < self.n_batches

        if should_capture:
            # ### HIGHLIGHT: Prefer explicit training_step outputs over forward monkey-patching
            # for robust train/audio capture.
            self._capturing_train_batch = True
        else:
            self._capturing_train_batch = False

    def on_train_batch_end(
        self,
        trainer: pl.Trainer,
        pl_module: pl.LightningModule,
        outputs: Any,
        batch: Any,
        batch_idx: int,
    ) -> None:
        # ### HIGHLIGHT: Keep non-zero ranks out of callback logging flow in DDP.
        if not trainer.is_global_zero:
            return

        if not self.on_train:
            return

        if self._capturing_train_batch:
            # ### HIGHLIGHT: Use detached tensors returned by training_step when available.
            if isinstance(outputs, dict):
                target = outputs.get("train_audio_target")
                recon = outputs.get("train_audio_reconstruction")
                if target is not None and recon is not None:
                    self._save_batch(target, "train", "target")
                    self._save_batch(recon, "train", "reconstruction")
            # Legacy fallback if train forward wrapping is re-enabled later.
            if hasattr(self, "stored_forward"):
                self._unwrap_forward()
            self._capturing_train_batch = False

    def on_train_epoch_end(
        self,
        trainer: pl.Trainer,
        pl_module: pl.LightningModule,
    ) -> None:
        if self.on_train:
            self._log_audio("train", trainer)
        self._clear_saved_batches("train")

    def on_validation_batch_start(
        self,
        trainer: pl.Trainer,
        pl_module: pl.LightningModule,
        batch: Any,
        batch_idx: int,
        dataloader_idx: int = 0,
    ) -> None:
        # ### HIGHLIGHT: Keep validation audio logging on rank 0 only.
        if not trainer.is_global_zero:
            return

        # ### HIGHLIGHT: Capture a rotated validation batch instead of always using batch 0.
        if (
            self.on_val
            and self._log_val_this_round
            and batch_idx == self._val_target_batch_idx
        ):
            self._wrap_forward("val")
            self._save_batch(batch[0], "val", "target")

    def on_validation_batch_end(
        self,
        trainer: pl.Trainer,
        pl_module: pl.LightningModule,
        outputs: Any,
        batch: Any,
        batch_idx: int,
        dataloader_idx: int = 0,
    ) -> None:
        # ### HIGHLIGHT: Keep validation audio logging on rank 0 only.
        if not trainer.is_global_zero:
            return

        # ### HIGHLIGHT: Finish capture for the currently selected validation batch.
        if (
            self.on_val
            and self._log_val_this_round
            and batch_idx == self._val_target_batch_idx
        ):
            self._unwrap_forward()

    # ### HIGHLIGHT: Select the next validation batch index for audio logging.
    def on_validation_start(
        self,
        trainer: pl.Trainer,
        pl_module: pl.LightningModule,
    ) -> None:
        # ### HIGHLIGHT: Keep validation audio scheduling on rank 0 only.
        if not trainer.is_global_zero:
            return

        if not self.on_val:
            return

        # ### HIGHLIGHT: De-duplicate val audio when multiple val runs happen in one epoch.
        self._log_val_this_round = True
        if trainer.state.fn == "fit":
            self._log_val_this_round = (
                int(trainer.current_epoch) != self._last_logged_val_audio_epoch
            )

        if not self._log_val_this_round:
            return

        num_val_batches = trainer.num_val_batches
        if isinstance(num_val_batches, (list, tuple)):
            num_val_batches = num_val_batches[0] if len(num_val_batches) > 0 else 0

        num_val_batches = max(int(num_val_batches), 1)
        self._val_target_batch_idx = self._val_round % num_val_batches
        self._val_round += 1

    def on_validation_epoch_end(
        self,
        trainer: pl.Trainer,
        pl_module: pl.LightningModule,
    ) -> None:
        # ### HIGHLIGHT: Keep validation audio logging on rank 0 only.
        if not trainer.is_global_zero:
            return

        if self.on_val and self._log_val_this_round:
            self._log_audio("val", trainer)
            if trainer.state.fn == "fit":
                self._last_logged_val_audio_epoch = int(trainer.current_epoch)
        self._clear_saved_batches("val")

    def on_test_batch_start(
        self,
        trainer: pl.Trainer,
        pl_module: pl.LightningModule,
        batch: Any,
        batch_idx: int,
        dataloader_idx: int,
    ) -> None:
        # ### HIGHLIGHT: Keep test audio logging on rank 0 only.
        if not trainer.is_global_zero:
            return

        if self.on_test and batch_idx < self.n_batches:
            self._wrap_forward("test")
            self._save_batch(batch[0], "test", "target")

    def on_test_batch_end(self, trainer, pl_module, outputs, batch, batch_idx: int, dataloader_idx: int = 0) -> None:
        # ### HIGHLIGHT: Keep test audio logging on rank 0 only.
        if not trainer.is_global_zero:
            return

        if not self.on_test:
            return

        if batch_idx < self.n_batches:
            self._unwrap_forward()

            if batch_idx == 0:
                self._log_audio("test", trainer)
                self._clear_saved_batches("test")

    def on_test_epoch_end(
        self,
        trainer: pl.Trainer,
        pl_module: pl.LightningModule,
    ) -> None:
        # ### HIGHLIGHT: Keep test audio logging on rank 0 only.
        if not trainer.is_global_zero:
            return

        if self.on_test and self.log_on_epoch_end:
            self._log_audio("test", trainer)
        self._clear_saved_batches("test")

    def _save_batch(
        self, batch: Any, split: str, type: Literal["target", "reconstruction"]
    ) -> None:
        batch = batch.detach().cpu()
        if type == "target":
            self.saved_targets[split].append(batch)
        elif type == "reconstruction":
            self.saved_reconstructions[split].append(batch)
        else:
            raise ValueError(f"Unknown type {type}")

    def _clear_saved_batches(self, split: str) -> None:
        self.saved_targets[split] = []
        self.saved_reconstructions[split] = []

    def _log_audio(self, split: str, trainer: pl.Trainer) -> None:
        if len(self.saved_targets[split]) == 0 or len(self.saved_reconstructions[split]) == 0:
            return

        # Different captured batches can have different padded time extents.
        # Flatten only their batch axes, then concatenate audio along time.
        targets = [item for batch in self.saved_targets[split] for item in batch]
        reconstructions = [item for batch in self.saved_reconstructions[split] for item in batch]

        if self.max_audio_samples is not None:
            targets = targets[: self.max_audio_samples]
            reconstructions = reconstructions[: self.max_audio_samples]

        signals = reduce(lambda x, y: x + y, zip(targets, reconstructions))
        audio_signal = torch.hstack(signals).cpu()
        # Use trainer.logger to avoid stale logger references during callback execution.
        logger = trainer.logger
        if isinstance(logger, WandbLogger) and trainer.is_global_zero:
            audio_signal = audio_signal.squeeze().numpy()
            # ### HIGHLIGHT: Unify W&B section names: val/* -> validation/*.
            split_key = "validation" if split == "val" else split
            audio = Audio(audio_signal, caption=f"{split_key}/audio", sample_rate=self.save_audio_sr)
            # ### HIGHLIGHT: Force audio x-axis near trainer/global_step while preserving
            # W&B monotonic-step requirement when mixed with Lightning auto logs.
            step = int(trainer.global_step)
            run = logger.experiment
            try:
                run_step = int(getattr(run, "step", -1))
                if step <= run_step:
                    step = run_step + 1
            except Exception:
                pass
            logger.experiment.log({f"{split_key}/audio": audio}, step=step)


class RunNameModelCheckpoint(ModelCheckpoint):
    """Store checkpoints under a run-specific subdirectory and prefix filenames."""

    @staticmethod
    def _resolve_run_name(trainer: pl.Trainer) -> str:
        default_root_dir = getattr(trainer, "default_root_dir", None)
        if isinstance(default_root_dir, str):
            default_root_dir = default_root_dir.strip()
            if default_root_dir:
                default_root = Path(default_root_dir).expanduser()
                # Explicit run folders can use `<logs>/<run_name>/lightning`.
                # Prefer that explicit run folder so checkpoint storage matches it.
                if default_root.name == "lightning" and default_root.parent.name:
                    return default_root.parent.name

        env_run_name = os.getenv("WANDB_NAME", "").strip()
        if env_run_name:
            return env_run_name

        logger = getattr(trainer, "logger", None)
        candidates = []
        if logger is not None:
            experiment = getattr(logger, "experiment", None)
            candidates.append(getattr(experiment, "name", None))
            logger_name = getattr(logger, "name", None)
            if not (
                isinstance(logger, WandbLogger)
                and logger_name == getattr(experiment, "project", None)
            ):
                candidates.append(logger_name)

        for value in candidates:
            if isinstance(value, str):
                value = value.strip()
                if value:
                    return value

        return ""

    def setup(
        self,
        trainer: pl.Trainer,
        pl_module: pl.LightningModule,
        stage: str,
    ) -> None:
        super().setup(trainer, pl_module, stage)

        run_name = self._resolve_run_name(trainer)
        if not run_name:
            return

        base_dir = self.dirpath or "checkpoints"
        if os.path.basename(os.path.normpath(base_dir)) != run_name:
            self.dirpath = os.path.join(base_dir, run_name)
        else:
            self.dirpath = base_dir

        filename = self.filename or "epoch{epoch:03d}-step{step:08d}"
        prefix = f"{run_name}-"
        if not filename.startswith(prefix):
            self.filename = f"{prefix}{filename}"
        else:
            self.filename = filename

        os.makedirs(self.dirpath, exist_ok=True)


class CleanWandbCacheCallback(pl.Callback):
    def __init__(self, every_n_epochs: int = 1, max_size_in_gb: float = 1.0):
        self.every_n_epochs = every_n_epochs
        self.gb_str = f"{max_size_in_gb}GB"

    def on_train_epoch_end(
        self, trainer: "pl.Trainer", pl_module: "pl.LightningModule"
    ) -> None:
        if trainer.current_epoch % self.every_n_epochs == 0:
            subprocess.Popen(["wandb", "artifact", "cache", "cleanup", self.gb_str])


class SaveConfigCallbackWanb(SaveConfigCallback):
    """
    Custom callback to move the config file saved by LightningCLI to the
    experiment directory created by WandbLogger. This has a few benefits:
    1. The config file is saved in the same directory as the other files created
         by wandb, so it's easier to find.
    2. The config file is uploaded to wandb and can be viewed in the UI.
    3. Subsequent runs won't be blocked by the config file already existing.
    """

    def __init__(self, *args, **kwargs) -> None:
        super().__init__(*args, **kwargs)

    @staticmethod
    def _write_runtime_context(trainer: pl.Trainer) -> None:
        if not trainer.is_global_zero:
            return

        raw = os.getenv("DRUMBLENDER_RUN_CONTEXT_JSON", "")
        if not raw:
            return

        try:
            payload = json.loads(raw)
        except Exception:
            payload = {"raw": raw}

        payload["saved_at_utc"] = datetime.now(timezone.utc).isoformat()
        payload["pytorch_lightning_log_dir"] = str(getattr(trainer, "log_dir", ""))

        log_dir = getattr(trainer, "log_dir", None)
        if not log_dir:
            return

        path = Path(log_dir) / "run-context.json"
        path.parent.mkdir(parents=True, exist_ok=True)
        with path.open("w", encoding="utf-8") as f:
            json.dump(payload, f, indent=2, ensure_ascii=False)

    def setup(
        self, trainer: pl.Trainer, pl_module: pl.LightningModule, stage: str
    ) -> None:
        super().setup(trainer, pl_module, stage)

        # ### HIGHLIGHT: Avoid touching wandb.experiment during DDP setup.
        # On some environments this can stall before the first training step.
        world_size = getattr(trainer, "world_size", 1)
        if world_size and int(world_size) > 1:
            return

        # ### HIGHLIGHT: Dump launch toggles/context only on non-DDP to avoid
        # distributed startup stalls caused by logger path resolution.
        self._write_runtime_context(trainer)

        if isinstance(trainer.logger, WandbLogger) and trainer.is_global_zero:
            config = Path(trainer.log_dir).joinpath("config.yaml")
            if not config.exists():
                return
            experiment_dir = Path(trainer.logger.experiment.dir)

            # If this is the first time using wandb logging on this machine,
            # the experiment directory won't exist yet.
            if not experiment_dir.exists():
                experiment_dir.mkdir(parents=True)

            config.rename(experiment_dir.joinpath("model-config.yaml"))

            # ### HIGHLIGHT: Mirror runtime context into the wandb run folder when available.
            run_ctx = Path(trainer.log_dir).joinpath("run-context.json")
            if run_ctx.exists():
                run_ctx_dst = experiment_dir.joinpath("run-context.json")
                if not run_ctx_dst.exists():
                    run_ctx_dst.write_text(run_ctx.read_text(encoding="utf-8"), encoding="utf-8")
