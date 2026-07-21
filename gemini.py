import os
import signal
import sys

os.environ["PYTORCH_CUDA_ALLOC_CONF"] = "expandable_segments:True"
os.environ.setdefault("WANDB_MODE", "online")

from dotenv import load_dotenv
load_dotenv()

import math
import torch
from datasets import load_from_disk
from transformers import (
    AutoTokenizer,
    AutoModelForCausalLM,
    BitsAndBytesConfig,
    DataCollatorForSeq2Seq,
    TrainingArguments,
    Trainer,
    TrainerCallback,
    set_seed,
)
from accelerate import Accelerator

from configuration_lora_moe import LoraMoeConfig
from modelling import LoraMoeModel
from training_config import TrainingConfig
from main import make_dataset

# ── Config ────────────────────────────────────────────────────────────────────
conf = TrainingConfig()

MODEL_ID             = conf.MODEL_ID
OUTPUT_DIR           = conf.OUTPUT_DIR
LOGDIR               = conf.LOGDIR
RUN_NAME             = conf.RUN_NAME
PROJECT_NAME         = conf.PROJECT_NAME
CONTEXT_LENGTH       = conf.CONTEXT_LENGTH
TRAIN_BATCH          = conf.TRAIN_BATCH
EVAL_BATCH           = conf.EVAL_BATCH
GRAD_ACCUM           = conf.GRAD_ACCUM
LR                   = conf.LR
NUM_EPOCHS           = conf.NUM_EPOCHS
MAX_STEPS            = conf.MAX_STEPS
EVAL_STEPS           = conf.EVAL_STEPS
LOGGING_STEPS        = conf.LOGGING_STEPS
NUM_CHECKPOINT_LIMIT = conf.NUM_CHECKPOINT_LIMIT
SEED                 = conf.SEED
NUM_EXPERTS          = conf.NUM_EXPERTS
NUM_EXPERTS_PER_TOK  = conf.NUM_EXPERTS_PER_TOK
SHARED_RANK          = conf.SHARED_RANK      # MALoRA: d, S_A's rank
EXPERT_RANK          = conf.EXPERT_RANK      # MALoRA: r_bar, P_t/B_bar_t's rank
ATTENTION_RANK       = conf.ATTENTION_RANK
EXPERTS_SCALE        = conf.EXPERTS_SCALE
EXPERTS_DROPOUT      = conf.EXPERTS_DROPOUT  # MALoRA: shared dropout rate
ROUTER_AUX_COEF      = conf.ROUTER_AUX_COEF
QUANTIZE             = conf.QUANTIZE
USE_8BIT_ADAM        = conf.USE_8BIT_ADAM
RESUME_FROM          = conf.RESUME_FROM
DS_PATH = conf.DS_PATH
WANDB_ID = conf.WANDB_ID
ATTENTION_LORA_ENABLED = conf.USE_LORA  # toggle here for aton/atoff runs


# ── QLoRA config ──────────────────────────────────────────────────────────────
def get_qlora_bnb_config() -> BitsAndBytesConfig:
    return BitsAndBytesConfig(
        load_in_4bit=True,
        bnb_4bit_use_double_quant=True,
        bnb_4bit_quant_type="nf4",
        bnb_4bit_compute_dtype=torch.bfloat16,
    )


# ── Auto-save on crash/interrupt ──────────────────────────────────────────────
_trainer_ref = None

def _emergency_save(signum, frame):
    global _trainer_ref
    print(f"\n[SIGNAL {signum}] Caught interrupt — saving emergency checkpoint...")
    if _trainer_ref is not None:
        try:
            emergency_dir = os.path.join(OUTPUT_DIR, "emergency_checkpoint")
            _trainer_ref.save_model(emergency_dir)
            print(f"Emergency checkpoint saved to {emergency_dir}")
        except Exception as e:
            print(f"Emergency save failed: {e}")
    sys.exit(0)

signal.signal(signal.SIGTERM, _emergency_save)
signal.signal(signal.SIGINT,  _emergency_save)


# ── Custom MoE Trainer ────────────────────────────────────────────────────────
class MoETrainer(Trainer):
    """
    Tracks aux loss, routing entropy, and per-expert usage telemetry.
    Works for both MoE-LoRA and MALoRA — only reads router output shape
    which is identical regardless of expert internals.
    """
    def __init__(self, tokenizer, *args, **kwargs):
        super().__init__(*args, **kwargs)
        self.tokenizer = tokenizer
        self._eval_aux_losses: list[float] = []
        self._routing_entropy: float = 0.0
        self._expert_usage: list[float] = []
        self._current_train_aux_loss: float = 0.0

    def compute_loss(self, model, inputs, return_outputs=False, **kwargs):
        # ── clamp labels to model's actual vocab size ──────────────────────
        labels = inputs.get("labels")
        if labels is not None:
            vocab_size = model.base_model.lm_head.weight.shape[0]
            invalid_mask = (labels >= vocab_size) | (labels < 0)
            labels = torch.where(
                invalid_mask,
                torch.tensor(-100, dtype=labels.dtype, device=labels.device),
                labels
            )
            inputs["labels"] = labels

        inputs["output_router_logits"] = True

        outputs = model(**inputs)
        loss = outputs.loss

        # ── aux loss tracking ─────────────────────────────────────────────
        if hasattr(outputs, "aux_loss") and outputs.aux_loss is not None:
            aux_val = outputs.aux_loss.detach().item()
            if model.training:
                self._current_train_aux_loss = aux_val
            else:
                self._eval_aux_losses.append(aux_val)

        # ── expert routing telemetry ──────────────────────────────────────
        if hasattr(outputs, "router_logits") and outputs.router_logits is not None and model.training:
            all_entropies = []
            all_usage     = []

            for layer_logits in outputs.router_logits:
                probs   = torch.softmax(layer_logits.float(), dim=-1)
                entropy = -(probs * torch.log(probs + 1e-9)).sum(dim=-1).mean()
                all_entropies.append(entropy.item())
                all_usage.append(probs.mean(dim=0).detach().cpu())

            self._routing_entropy = sum(all_entropies) / len(all_entropies)
            self._expert_usage    = torch.stack(all_usage).mean(dim=0).tolist()

        return (loss, outputs) if return_outputs else loss

    def log(self, logs: dict, start_time=None) -> None:
        if hasattr(self, "_current_train_aux_loss"):
            logs["train_aux_loss"] = self._current_train_aux_loss

        if self._routing_entropy:
            logs["routing_entropy"] = round(self._routing_entropy, 4)

        if self._expert_usage:
            for i, usage in enumerate(self._expert_usage):
                logs[f"expert_{i}_pct"] = round(usage * 100, 2)

        if "loss" in logs:
            try:
                logs["train_perplexity"] = math.exp(logs["loss"])
            except OverflowError:
                logs["train_perplexity"] = float("inf")

        super().log(logs, start_time)

    def evaluate(self, eval_dataset=None, ignore_keys=None, metric_key_prefix="eval"):
        self._eval_aux_losses.clear()
        metrics = super().evaluate(eval_dataset, ignore_keys, metric_key_prefix)

        if self._eval_aux_losses:
            metrics[f"{metric_key_prefix}_aux_loss"] = (
                sum(self._eval_aux_losses) / len(self._eval_aux_losses)
            )

        if f"{metric_key_prefix}_loss" in metrics:
            try:
                metrics[f"{metric_key_prefix}_perplexity"] = math.exp(
                    metrics[f"{metric_key_prefix}_loss"]
                )
            except OverflowError:
                metrics[f"{metric_key_prefix}_perplexity"] = float("inf")

        return metrics

    def _remove_unused_columns(self, dataset, description=None):
        # keep all columns — our custom collator handles filtering
        return dataset


# ── WandB Callback ────────────────────────────────────────────────────────────
class WandbConfigCallback(TrainerCallback):
    def on_train_begin(self, args, state, control, **kwargs):
        try:
            import wandb
            if wandb.run is not None:
                wandb.config.update({
                    "model_id":          MODEL_ID,
                    "lr":                LR,
                    "num_epochs":        NUM_EPOCHS,
                    "num_experts":       NUM_EXPERTS,
                    "shared_rank":       SHARED_RANK,
                    "expert_rank":       EXPERT_RANK,
                    "attention_rank":    ATTENTION_RANK,
                    "attn_lora_enabled": ATTENTION_LORA_ENABLED,
                    "context_length":    CONTEXT_LENGTH,
                    "train_batch":       TRAIN_BATCH,
                    "grad_accum":        GRAD_ACCUM,
                }, allow_val_change=True)
        except ImportError:
            pass


# ── Checkpoint resume helper ──────────────────────────────────────────────────
def resolve_checkpoint(resume_from: str | None, accelerator: Accelerator) -> str | None:
    if not resume_from:
        return None

    resume_from = os.path.normpath(os.path.expanduser(resume_from))

    if "checkpoint-" in os.path.basename(resume_from):
        pass
    else:
        checkpoints = sorted(
            [x for x in os.listdir(resume_from) if x.startswith("checkpoint-")],
            key=lambda x: int(x.split("-")[-1]),
        )
        if not checkpoints:
            raise ValueError(f"No checkpoints found in {resume_from}")
        resume_from = os.path.join(resume_from, checkpoints[-1])

    if accelerator.is_main_process:
        print(f"Resuming from: {resume_from}")

    return resume_from


# ── Main ──────────────────────────────────────────────────────────────────────
def main():
    global _trainer_ref

    accelerator = Accelerator()
    resume_from = resolve_checkpoint(RESUME_FROM, accelerator)

    os.environ["WANDB_PROJECT"] = PROJECT_NAME
    os.environ["WANDB_ENTITY"]  = WANDB_ID

    if accelerator.is_main_process:
        import wandb
        wandb.init(project=PROJECT_NAME, name=RUN_NAME, resume="allow")

    set_seed(SEED)

    # ── Tokenizer ─────────────────────────────────────────────────────────────
    if accelerator.is_main_process:
        print("Loading tokenizer...")

    tokenizer = AutoTokenizer.from_pretrained(MODEL_ID, trust_remote_code=True)
    if tokenizer.pad_token_id is None:
        tokenizer.pad_token_id = tokenizer.eos_token_id
    tokenizer.padding_side    = "right"
    tokenizer.truncation_side = "left"

    # ── Datasets ──────────────────────────────────────────────────────────────
    with accelerator.main_process_first():
        tp = os.path.join(DS_PATH, "train")
        ep = os.path.join(DS_PATH, "eval")
        if os.path.exists(tp) and os.path.exists(ep):
            if accelerator.is_main_process:
                print("Loading datasets from disk...")
            train_dataset = load_from_disk(tp)
            eval_dataset  = load_from_disk(ep)
        else:
            if accelerator.is_main_process:
                print("Datasets not found — running make_dataset()...")
            #make_dataset()
            train_dataset = load_from_disk(tp)
            eval_dataset  = load_from_disk(ep)

    tensor_cols   = ["input_ids", "attention_mask", "labels"]
    train_dataset = train_dataset.select_columns([c for c in tensor_cols if c in train_dataset.column_names])
    eval_dataset  = eval_dataset.select_columns([c for c in tensor_cols  if c in eval_dataset.column_names])

    data_collator = DataCollatorForSeq2Seq(
        tokenizer=tokenizer,
        padding=True,
        pad_to_multiple_of=8,
        label_pad_token_id=-100,
    )

    # ── Base model ────────────────────────────────────────────────────────────
    if accelerator.is_main_process:
        print("Loading base model...")
        print(f"  QUANTIZE = {QUANTIZE}  ({'4-bit QLoRA' if QUANTIZE else 'full bf16 (no quantization)'})")

    bnb_config = get_qlora_bnb_config() if QUANTIZE else None

    base_model = AutoModelForCausalLM.from_pretrained(
        MODEL_ID,
        quantization_config=bnb_config,
        device_map={"": accelerator.local_process_index} if QUANTIZE else None,
        trust_remote_code=True,
        torch_dtype=torch.bfloat16,
        attn_implementation="sdpa",
    )

    if not QUANTIZE:
        base_model = base_model.to(accelerator.device)

    base_model.enable_input_require_grads()
    base_model.config.use_cache = False

    # ── MALoRA wrap ───────────────────────────────────────────────────────────
    if accelerator.is_main_process:
        print("Wrapping with MALoRA...")

    moe_config = LoraMoeConfig.from_pretrained(MODEL_ID)
    moe_config.shared_rank          = SHARED_RANK
    moe_config.expert_rank          = EXPERT_RANK
    moe_config.attention_rank       = ATTENTION_RANK
    moe_config.experts_scale        = EXPERTS_SCALE
    moe_config.experts_dropout      = EXPERTS_DROPOUT
    moe_config.num_experts_per_tok  = NUM_EXPERTS_PER_TOK
    moe_config.num_local_experts    = NUM_EXPERTS
    moe_config.output_router_logits = True
    moe_config.router_aux_loss_coef = ROUTER_AUX_COEF
    moe_config.use_attention_lora   = ATTENTION_LORA_ENABLED

    moe_model = LoraMoeModel(base_model, moe_config)
    moe_model.make_experts_trainable()
    moe_model.base_model.gradient_checkpointing_enable()
    moe_model.base_model.config.use_cache = False

    if accelerator.is_main_process:
        trainable = sum(p.numel() for p in moe_model.parameters() if p.requires_grad)
        total     = sum(p.numel() for p in moe_model.parameters())
        print(f"Trainable: {trainable/1e6:.1f}M / {total/1e6:.0f}M ({100*trainable/total:.2f}%)")

        active_dtypes   = {}
        inactive_dtypes = {}
        for p in moe_model.parameters():
            key = str(p.dtype)
            if p.requires_grad:
                active_dtypes[key]   = active_dtypes.get(key, 0) + 1
            else:
                inactive_dtypes[key] = inactive_dtypes.get(key, 0) + 1
        print("Active dtypes:",   active_dtypes)
        print("Inactive dtypes:", inactive_dtypes)

        if torch.cuda.is_available():
            allocated = torch.cuda.memory_allocated() / 1e9
            reserved  = torch.cuda.memory_reserved()  / 1e9
            total_mem = torch.cuda.get_device_properties(0).total_memory / 1e9
            print(f"VRAM after model wrap: {allocated:.2f}GB allocated / {reserved:.2f}GB reserved / {total_mem:.2f}GB total")

    # ── Training args ─────────────────────────────────────────────────────────
    training_args = TrainingArguments(
        output_dir=OUTPUT_DIR,
        num_train_epochs=NUM_EPOCHS,
        per_device_train_batch_size=TRAIN_BATCH,
        per_device_eval_batch_size=EVAL_BATCH,
        gradient_accumulation_steps=GRAD_ACCUM,
        learning_rate=LR,
        max_steps=MAX_STEPS,
        optim="adamw_bnb_8bit" if USE_8BIT_ADAM else "adamw_torch",
        lr_scheduler_type="cosine_with_restarts",
        warmup_ratio=0.1,
        gradient_checkpointing=True,
        gradient_checkpointing_kwargs={"use_reentrant": False},
        dataloader_num_workers=8,
        dataloader_pin_memory=True,
        eval_strategy="steps",
        eval_steps=EVAL_STEPS,
        logging_strategy="steps",
        logging_steps=LOGGING_STEPS,
        logging_dir=LOGDIR,
        run_name=RUN_NAME,
        bf16=True,
        fp16=False,
        max_grad_norm=0.3,
        seed=SEED,
        save_total_limit=NUM_CHECKPOINT_LIMIT,
        save_strategy="steps",
        save_steps=EVAL_STEPS,
        report_to="wandb",
        remove_unused_columns=False,
        load_best_model_at_end=False,
        greater_is_better=False,
    )

    # ── Trainer ───────────────────────────────────────────────────────────────
    trainer = MoETrainer(
        tokenizer=tokenizer,
        model=moe_model,
        args=training_args,
        train_dataset=train_dataset,
        eval_dataset=eval_dataset,
        data_collator=data_collator,
        processing_class=tokenizer,
        callbacks=[WandbConfigCallback()],
    )

    _trainer_ref = trainer

    # ── Train ─────────────────────────────────────────────────────────────────
    if accelerator.is_main_process:
        print("\nStarting training...")
        print(f"  Steps per epoch: {len(train_dataset) // (TRAIN_BATCH * GRAD_ACCUM)}")
        print(f"  Total steps: {MAX_STEPS if MAX_STEPS > 0 else 'full'}")

    trainer.train(resume_from_checkpoint=resume_from)

    # ── Save ──────────────────────────────────────────────────────────────────
    if accelerator.is_main_process:
        trainer.save_model(OUTPUT_DIR)
        tokenizer.save_pretrained(OUTPUT_DIR)
        print(f"\nTraining complete. Model saved to {OUTPUT_DIR}")


if __name__ == "__main__":
    main()