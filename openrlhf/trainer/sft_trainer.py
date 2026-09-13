import os
from abc import ABC

import torch
from torch.optim import Optimizer
from tqdm import tqdm

from openrlhf.models import SFTLoss
from openrlhf.utils.distributed_sampler import DistributedSampler
from openrlhf.utils.loss_utils import iter_grad_accum_global_norm


class SFTTrainer(ABC):
    """
    Trainer for supervised fine-tuning (SFT).

    Args:
        model (torch.nn.Module): The model to be trained.
        strategy (Strategy): The training strategy to be applied.
        optim (Optimizer): The optimizer for model training.
        train_dataloader (DataLoader): The dataloader for the training dataset.
        eval_dataloader (DataLoader): The dataloader for the evaluation dataset.
        scheduler (Scheduler): The learning rate scheduler to adjust training rates.
        max_norm (float, defaults to 1): Maximum gradient norm for clipping to prevent exploding gradients.
        pretrain_mode (bool, defaults to False): Flag to indicate if the trainer is in pre-training mode.
        batch_size (int, defaults to 1): Batch size for training.
        max_epochs (int, defaults to 2): The maximum number of training epochs.
        tokenizer (Tokenizer, optional): The tokenizer for processing input data.
        save_hf_ckpt (bool): Whether to save huggingface-format model weight.
        disable_ds_ckpt (bool): Whether not to save deepspeed-format model weight. (Deepspeed model weight is used for training recovery)
    """

    def __init__(
        self,
        model,
        strategy,
        optim: Optimizer,
        train_dataloader,
        eval_dataloader,
        scheduler,
        max_norm: float = 1,
        pretrain_mode: bool = False,
        batch_size: int = 1,
        max_epochs: int = 2,
        tokenizer=None,
        save_hf_ckpt: bool = False,
        disable_ds_ckpt: bool = False,
    ) -> None:
        super().__init__()
        self.strategy = strategy
        self.epochs = max_epochs
        self.batch_size = batch_size
        self.max_norm = max_norm
        self.train_dataloader = train_dataloader
        self.eval_dataloader = eval_dataloader
        self.scheduler = scheduler
        self.pretrain_mode = pretrain_mode
        self.model = model
        self.tokenizer = tokenizer
        self.optimizer = optim
        self.args = strategy.args
        self.save_hf_ckpt = save_hf_ckpt
        self.disable_ds_ckpt = disable_ds_ckpt

        self.loss_fn = SFTLoss()

        # Mixtral 8*7b
        self.aux_loss = self.args.model.aux_loss_coef > 1e-8

        # packing samples
        self.packing_samples = strategy.args.ds.packing_samples

        # wandb/tensorboard setting
        self._wandb = None
        self._tensorboard = None
        if self.strategy.args.logger.wandb.key and self.strategy.is_rank_0():
            import wandb

            self._wandb = wandb
            if not wandb.api.api_key:
                wandb.login(key=strategy.args.logger.wandb.key)
            wandb.init(
                entity=strategy.args.logger.wandb.org,
                project=strategy.args.logger.wandb.project,
                group=strategy.args.logger.wandb.group,
                name=strategy.args.logger.wandb.run_name,
                config=strategy.args.__dict__,
                reinit=True,
            )

            wandb.define_metric("train/global_step")
            wandb.define_metric("train/*", step_metric="train/global_step", step_sync=True)
            wandb.define_metric("eval/global_step")
            wandb.define_metric("eval/*", step_metric="eval/global_step", step_sync=True)

        # Initialize TensorBoard writer if wandb is not available
        if self.strategy.args.logger.tensorboard_dir and self._wandb is None and self.strategy.is_rank_0():
            from torch.utils.tensorboard import SummaryWriter

            os.makedirs(self.strategy.args.logger.tensorboard_dir, exist_ok=True)
            log_dir = os.path.join(self.strategy.args.logger.tensorboard_dir, strategy.args.logger.wandb.run_name)
            self._tensorboard = SummaryWriter(log_dir=log_dir)

    def fit(self, args, consumed_samples=0, num_update_steps_per_epoch=None):
        accumulated_gradient = self.strategy.accumulated_gradient
        # Infer num_update_steps_per_epoch from dataloader if not provided
        if num_update_steps_per_epoch is None:
            num_update_steps_per_epoch = max(1, len(self.train_dataloader) // accumulated_gradient)
        if num_update_steps_per_epoch <= 0 or len(self.train_dataloader) * self.epochs < accumulated_gradient:
            raise ValueError(
                "Training must contain at least one complete gradient-accumulation window "
                "and num_update_steps_per_epoch must be positive."
            )

        # get eval and save steps
        if args.eval.steps == -1:
            args.eval.steps = num_update_steps_per_epoch
        if args.ckpt.save_steps == -1:
            args.ckpt.save_steps = float("inf")  # do not save ckpt

        # Restore the data position independently of optimizer windows, which may span epochs.
        samples_per_micro_batch = args.train.batch_size // accumulated_gradient
        samples_per_epoch = len(self.train_dataloader) * samples_per_micro_batch
        start_epoch, consumed_in_epoch = divmod(consumed_samples, samples_per_epoch)
        engine = self.model.model

        epoch_bar = tqdm(
            range(start_epoch, self.epochs),
            desc="Train epoch",
            disable=not self.strategy.is_rank_0(),
        )
        loss_sum = 0
        window = []
        for epoch in range(start_epoch, self.epochs):
            if isinstance(self.train_dataloader.sampler, DistributedSampler):
                self.train_dataloader.sampler.set_epoch(
                    epoch, consumed_samples=0 if epoch > start_epoch else consumed_in_epoch
                )

            num_micro_batches = len(self.train_dataloader)
            step_bar = tqdm(
                range(num_micro_batches),
                desc="Train step of epoch %d" % epoch,
                disable=not self.strategy.is_rank_0(),
            )

            # train
            self.model.train()
            device = next(self.model.parameters()).device

            # Normalize the loss by the global token count of the whole optimizer-step window
            # (not per micro-batch). mask_fn extracts the shifted loss mask -- the same mask
            # aggregate_loss reduces over -- from each (inputs, attention_masks, loss_masks) batch.
            def sft_loss_mask(batch):
                return batch[2].squeeze(1)[:, :-1]

            # Keep normalization windows aligned with DeepSpeed's fixed-size updates across epochs.
            # A final incomplete window cannot update the model and is left unused, as before.
            for batch in self.train_dataloader:
                window.append(batch)
                step_bar.update()
                if len(window) < accumulated_gradient:
                    continue

                for (inputs, attention_masks, loss_masks), loss_batch_info in iter_grad_accum_global_norm(
                    window, self.strategy, accumulated_gradient, sft_loss_mask
                ):
                    inputs = inputs.to(device).squeeze(1)
                    attention_mask = attention_masks.to(device).squeeze(1)
                    loss_mask = loss_masks.to(device).squeeze(1)
                    per_token_log_probs, output = self.model(
                        inputs,
                        attention_mask=attention_mask,
                        return_output=True,
                        return_logprobs=True,
                        ring_attn_group=self.strategy.ring_attn_group,
                    )

                    # mixtral
                    if self.aux_loss:
                        aux_loss = output.aux_loss
                    else:
                        aux_loss = 0
                    shifted_loss_mask = loss_mask[:, :-1]
                    gpt_loss = self.loss_fn(
                        per_token_log_probs,
                        shifted_loss_mask,
                        **loss_batch_info,
                    )
                    loss = gpt_loss + aux_loss * self.args.model.aux_loss_coef
                    self.strategy.backward(loss, self.model, self.optimizer)
                    self.strategy.optimizer_step(self.optimizer, self.model, self.scheduler)
                    consumed_samples += samples_per_micro_batch

                    loss_sum += gpt_loss.item()
                    logs_dict = {
                        "gpt_loss": gpt_loss.item(),
                        "lr": self.scheduler.get_last_lr()[0],
                        "grad_norm": self.strategy.get_grad_norm(self.model),
                    }
                    if self.aux_loss:
                        logs_dict["aux_loss"] = aux_loss.item()
                    # step bar
                    logs_dict = self.strategy.all_reduce(logs_dict)
                    step_bar.set_postfix(logs_dict)

                # Every emitted window is one complete optimizer update.
                logs_dict["loss_mean"] = loss_sum / accumulated_gradient
                loss_sum = 0
                client_states = {"consumed_samples": consumed_samples}
                self.save_logs_and_checkpoints(args, engine.global_steps, step_bar, logs_dict, client_states)

                window.clear()

            epoch_bar.update()

        if self._wandb is not None and self.strategy.is_rank_0():
            self._wandb.finish()
        if self._tensorboard is not None and self.strategy.is_rank_0():
            self._tensorboard.close()

    # logs/checkpoints/evaluation
    def save_logs_and_checkpoints(self, args, global_step, step_bar, logs_dict=None, client_states=None):
        logs_dict = logs_dict or {}
        client_states = client_states or {}
        if global_step % args.logger.logging_steps == 0:
            # wandb
            if self._wandb is not None and self.strategy.is_rank_0():
                logs = {"train/%s" % k: v for k, v in {**logs_dict, "global_step": global_step}.items()}
                self._wandb.log(logs)
            # TensorBoard
            elif self._tensorboard is not None and self.strategy.is_rank_0():
                for k, v in logs_dict.items():
                    self._tensorboard.add_scalar(f"train/{k}", v, global_step)

        # eval
        if global_step % args.eval.steps == 0:
            # do eval when eval_dataloader is not None and len(dataloader) > 0, avoid zero division in eval.
            if self.eval_dataloader is not None and len(self.eval_dataloader) > 0:
                self.evaluate(self.eval_dataloader, global_step)

        # save ckpt
        # TODO: save best model on dev, use loss/perplexity on whole dev dataset as metric
        if global_step % args.ckpt.save_steps == 0:
            tag = f"global_step{global_step}"
            if not self.disable_ds_ckpt:
                self.strategy.save_ckpt(
                    self.model.model, args.ckpt.path, tag, args.ckpt.max_num, args.ckpt.max_mem, client_states
                )
            if self.save_hf_ckpt:
                save_path = os.path.join(args.ckpt.path, f"{tag}_hf")
                self.strategy.save_model(self.model, self.tokenizer, save_path)

    def evaluate(self, eval_dataloader, steps=0):
        times = 0
        self.model.eval()
        with torch.no_grad():
            loss_sum = 0
            step_bar = tqdm(
                range(eval_dataloader.__len__()),
                desc="Eval stage of steps %d" % steps,
                disable=not self.strategy.is_rank_0(),
            )

            device = next(self.model.parameters()).device
            for inputs, attention_masks, loss_masks in eval_dataloader:
                inputs = inputs.to(device).squeeze(1)
                attention_mask = attention_masks.to(device).squeeze(1)
                loss_mask = loss_masks.to(device).squeeze(1)
                per_token_log_probs = self.model(
                    inputs,
                    attention_mask=attention_mask,
                    return_logprobs=True,
                    ring_attn_group=self.strategy.ring_attn_group,
                )

                loss = self.loss_fn(per_token_log_probs, loss_mask[:, :-1])

                times += 1
                loss_sum += loss.item()
                bar_dict = {"eval gpt_loss": loss_sum / times}
                step_bar.update()
                logs = self.strategy.all_reduce(bar_dict)
                step_bar.set_postfix(logs)

            if self.strategy.is_rank_0():
                if self._wandb is not None:
                    logs = {"eval/%s" % k: v for k, v in {**logs, "global_step": steps}.items()}
                    self._wandb.log(logs)
                elif self._tensorboard is not None:
                    for k, v in logs.items():
                        self._tensorboard.add_scalar(f"eval/{k}", v, steps)
        self.model.train()  # reset model state
