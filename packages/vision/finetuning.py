#!/usr/bin/env python3
# -*- coding: utf-8 -*-
"""
LoRA Fine-tuning for TrOCR — Handwriting Recognition
=====================================================
Fine-tune Microsoft TrOCR on custom handwriting data using PEFT/LoRA.

Features:
  - JSONL training data loading
  - Data augmentation (rotation, brightness, noise)
  - Train/val split with metrics
  - Automatic model save and hot-reload
  - WER/CER evaluation after training

Usage:
  from packages.vision.finetuning import TrOCRFinetuner
  tuner = TrOCRFinetuner(model_name="microsoft/trocr-base-handwritten")
  tuner.train(
      train_jsonl="training_data/train.jsonl",
      val_jsonl="training_data/val.jsonl",
      images_dir="training_data/",
      output_dir="./finetuned_model",
      epochs=5,
  )

Author:  Dr Abdulmalek Tamer Al-husseini
License: MIT
"""

import io
import json
import logging
import os
import time
from datetime import datetime
from pathlib import Path
from typing import Dict, List, Optional, Tuple

import numpy as np

logger = logging.getLogger(__name__)


class TrOCRFinetuner:
    """
    Fine-tune TrOCR with LoRA on custom handwriting data.

    The trainer loads word-level images with text labels from JSONL files,
    applies optional augmentation, and trains LoRA adapters.
    """

    def __init__(
        self,
        model_name: str = "microsoft/trocr-base-handwritten",
        cache_dir: str = "/data/.cache/huggingface",
        device: str = "auto",
    ):
        self.model_name = model_name
        self.cache_dir = cache_dir
        self.device = device

        if device == "auto":
            try:
                import torch
                self.device = "cuda" if torch.cuda.is_available() else "cpu"
            except ImportError:
                self.device = "cpu"

        self._processor = None
        self._tokenizer = None
        self._loaded_model = None

    def _load_processor(self):
        """Lazy-load the TrOCR processor and tokenizer."""
        if self._processor is not None:
            return
        try:
            from transformers import TrOCRProcessor
            self._processor = TrOCRProcessor.from_pretrained(
                self.model_name, cache_dir=self.cache_dir
            )
        except Exception as e:
            logger.error("Failed to load TrOCR processor: %s", e)
            raise

    def train(
        self,
        train_jsonl: str,
        images_dir: str,
        output_dir: str,
        val_jsonl: Optional[str] = None,
        epochs: int = 5,
        batch_size: int = 4,
        learning_rate: float = 1e-5,
        lora_r: int = 16,
        lora_alpha: int = 32,
        lora_dropout: float = 0.1,
        lora_target_modules: Optional[List[str]] = None,
        max_label_length: int = 64,
        enable_augmentation: bool = True,
        augment_rotation: float = 3.0,
        augment_brightness: float = 0.2,
        min_samples: int = 10,
    ) -> Dict:
        """
        Fine-tune TrOCR with LoRA.

        Args:
            train_jsonl: Path to training JSONL file
            images_dir: Base directory for images (prepended to image paths in JSONL)
            val_jsonl: Optional validation JSONL file
            output_dir: Directory to save the fine-tuned model
            epochs: Number of training epochs
            batch_size: Batch size for training
            learning_rate: Learning rate for AdamW optimizer
            lora_r: LoRA rank
            lora_alpha: LoRA alpha
            lora_dropout: LoRA dropout
            lora_target_modules: Target modules for LoRA (default: ["query", "value"])
            max_label_length: Maximum token length for labels
            enable_augmentation: Apply random augmentation during training
            augment_rotation: Max rotation angle in degrees
            augment_brightness: Max brightness change factor
            min_samples: Minimum number of samples required to start training

        Returns:
            Training statistics dict
        """
        # Load processor
        self._load_processor()

        # Load training data
        train_data = self._load_jsonl(train_jsonl, images_dir)
        if len(train_data) < min_samples:
            return {
                "status": "skipped",
                "reason": f"Not enough samples: {len(train_data)} < {min_samples}",
            }

        val_data = []
        if val_jsonl and os.path.isfile(val_jsonl):
            val_data = self._load_jsonl(val_jsonl, images_dir)

        logger.info(
            "Training: %d samples | Validation: %d samples | Device: %s",
            len(train_data), len(val_data), self.device,
        )

        # Import dependencies
        try:
            import torch
            from torch.optim import AdamW
            from torch.utils.data import Dataset, DataLoader
            from transformers import VisionEncoderDecoderModel, TrOCRProcessor
            from peft import get_peft_model, LoraConfig, TaskType
        except ImportError as e:
            return {"status": "error", "reason": f"Missing dependency: {e}"}

        if lora_target_modules is None:
            lora_target_modules = ["query", "value"]

        # Load base model
        logger.info("Loading base model: %s", self.model_name)
        model = VisionEncoderDecoderModel.from_pretrained(
            self.model_name, cache_dir=self.cache_dir
        )
        model.to(self.device)

        # Setup LoRA
        lora_config = LoraConfig(
            task_type=TaskType.SEQ_2_SEQ_LM,
            r=lora_r,
            lora_alpha=lora_alpha,
            target_modules=lora_target_modules,
            lora_dropout=lora_dropout,
        )
        model = get_peft_model(model, lora_config)
        model.print_trainable_parameters()
        model.train()

        # Dataset
        pad_token_id = self._processor.tokenizer.pad_token_id

        class HandwritingDataset(Dataset):
            def __init__(self, records, processor, augment=False):
                self.records = records
                self.processor = processor
                self.augment = augment

            def __len__(self):
                return len(self.records)

            def __getitem__(self, idx):
                rec = self.records[idx]
                img = rec["image"]
                text = rec["text"]

                # Augmentation
                if self.augment:
                    img = self._augment(img)

                pixel_values = self.processor(images=img, return_tensors="pt").pixel_values.squeeze(0)
                labels = self.processor.tokenizer(
                    text, return_tensors="pt", padding="max_length",
                    max_length=max_label_length,
                ).input_ids.squeeze(0)
                labels[labels == pad_token_id] = -100
                return {"pixel_values": pixel_values, "labels": labels}

            @staticmethod
            def _augment(img):
                """Basic augmentation: rotation + brightness."""
                import random
                # Random rotation
                if random.random() < 0.3:
                    angle = random.uniform(-augment_rotation, augment_rotation)
                    img = img.rotate(angle, expand=False, fillcolor=(255, 255, 255))
                # Random brightness (via numpy)
                if random.random() < 0.3:
                    arr = np.array(img).astype(np.float32)
                    factor = 1.0 + random.uniform(-augment_brightness, augment_brightness)
                    arr = np.clip(arr * factor, 0, 255).astype(np.uint8)
                    from PIL import Image as PILImage
                    img = PILImage.fromarray(arr)
                return img

        train_dataset = HandwritingDataset(train_data, self._processor, augment=enable_augmentation)
        train_loader = DataLoader(train_dataset, batch_size=batch_size, shuffle=True)

        val_loader = None
        if val_data:
            val_dataset = HandwritingDataset(val_data, self._processor, augment=False)
            val_loader = DataLoader(val_dataset, batch_size=batch_size, shuffle=False)

        optimizer = AdamW(model.parameters(), lr=learning_rate)

        # Training loop
        history = {"train_loss": [], "val_loss": [], "epoch_times": []}
        start_time = time.time()

        for epoch in range(epochs):
            epoch_start = time.time()
            total_loss = 0.0
            batch_count = 0

            model.train()
            for batch in train_loader:
                pixel_values = batch["pixel_values"].to(self.device)
                labels = batch["labels"].to(self.device)

                outputs = model(pixel_values=pixel_values, labels=labels)
                loss = outputs.loss
                loss.backward()
                optimizer.step()
                optimizer.zero_grad()

                total_loss += loss.item()
                batch_count += 1

            avg_train_loss = total_loss / max(batch_count, 1)
            history["train_loss"].append(avg_train_loss)

            # Validation
            avg_val_loss = 0.0
            if val_loader:
                model.eval()
                val_loss = 0.0
                val_count = 0
                with torch.no_grad():
                    for batch in val_loader:
                        pixel_values = batch["pixel_values"].to(self.device)
                        labels = batch["labels"].to(self.device)
                        outputs = model(pixel_values=pixel_values, labels=labels)
                        val_loss += outputs.loss.item()
                        val_count += 1
                avg_val_loss = val_loss / max(val_count, 1)
                history["val_loss"].append(avg_val_loss)
                model.train()

            epoch_time = time.time() - epoch_start
            history["epoch_times"].append(epoch_time)

            logger.info(
                "Epoch %d/%d | Train Loss: %.4f | Val Loss: %.4f | Time: %.1fs",
                epoch + 1, epochs, avg_train_loss, avg_val_loss, epoch_time,
            )

        # Save model
        os.makedirs(output_dir, exist_ok=True)
        model.save_pretrained(output_dir)
        self._processor.save_pretrained(output_dir)

        # Save training config
        config_data = {
            "base_model": self.model_name,
            "epochs": epochs,
            "batch_size": batch_size,
            "learning_rate": learning_rate,
            "lora_r": lora_r,
            "lora_alpha": lora_alpha,
            "train_samples": len(train_data),
            "val_samples": len(val_data),
            "history": history,
            "timestamp": datetime.now().isoformat(),
            "device": self.device,
        }
        config_path = os.path.join(output_dir, "training_config.json")
        with open(config_path, "w", encoding="utf-8") as f:
            json.dump(config_data, f, ensure_ascii=False, indent=2)

        total_time = time.time() - start_time
        logger.info("Training complete in %.1fs. Model saved to: %s", total_time, output_dir)

        return {
            "status": "success",
            "output_dir": output_dir,
            "train_samples": len(train_data),
            "val_samples": len(val_data),
            "epochs": epochs,
            "final_train_loss": history["train_loss"][-1] if history["train_loss"] else 0,
            "final_val_loss": history["val_loss"][-1] if history["val_loss"] else 0,
            "total_time_sec": round(total_time, 2),
            "history": history,
        }

    # ----------------------------------------------------------------
    # Hot-Reload & Inference
    # ----------------------------------------------------------------

    def hot_reload(self, model_path: str) -> Dict:
        """
        Load fine-tuned LoRA adapters and return the model ready for inference.
        This allows immediate use of the fine-tuned model without restarting.
        """
        try:
            import torch
            from transformers import VisionEncoderDecoderModel
            from peft import PeftModel
        except ImportError:
            return {"status": "error", "reason": "Missing dependencies"}

        base_model = VisionEncoderDecoderModel.from_pretrained(
            self.model_name, cache_dir=self.cache_dir
        )
        model = PeftModel.from_pretrained(base_model, model_path)
        model.to(self.device)
        model.eval()

        # Also reload processor from fine-tuned dir (may have custom tokenizer)
        try:
            from transformers import TrOCRProcessor
            self._processor = TrOCRProcessor.from_pretrained(model_path)
        except Exception:
            logger.warning("Could not load processor from %s, using base processor", model_path)

        self._loaded_model = model  # Store for inference use
        return {
            "status": "success",
            "model_path": model_path,
            "device": self.device,
            "message": "Model loaded and ready for inference",
        }

    def predict(self, image, model_path: str = None) -> str:
        """
        Run inference on a single image using the fine-tuned model.
        Falls back to the hot-loaded model if model_path is not provided.
        """
        import torch
        from transformers import VisionEncoderDecoderModel, TrOCRProcessor
        from peft import PeftModel

        model = getattr(self, '_loaded_model', None)
        if model is None and model_path:
            result = self.hot_reload(model_path)
            if result["status"] != "success":
                return ""
            model = self._loaded_model
        if model is None:
            return ""

        self._load_processor()
        pixel_values = self._processor(images=image, return_tensors="pt").pixel_values.to(self.device)
        with torch.no_grad():
            generated = model.generate(pixel_values)
        return self._processor.tokenizer.decode(generated[0], skip_special_tokens=True)

    # ----------------------------------------------------------------
    # Data Loading
    # ----------------------------------------------------------------

    def _load_jsonl(self, jsonl_path: str, images_dir: str) -> List[Dict]:
        """Load JSONL training data with images."""
        records = []
        with open(jsonl_path, "r", encoding="utf-8") as f:
            for line_num, line in enumerate(f, 1):
                line = line.strip()
                if not line:
                    continue
                try:
                    rec = json.loads(line)
                    img_path = os.path.join(images_dir, rec.get("image", ""))
                    text = rec.get("text", "").strip()

                    if not os.path.isfile(img_path) or not text:
                        continue

                    from PIL import Image
                    img = Image.open(img_path).convert("RGB")
                    records.append({"image": img, "text": text})
                except Exception as e:
                    logger.warning("Skipping line %d in %s: %s", line_num, jsonl_path, e)

        return records

    def evaluate(self, model_path: str, test_jsonl: str, images_dir: str) -> Dict:
        """Evaluate fine-tuned model on test data. Returns WER/CER metrics."""
        try:
            import torch
            from transformers import VisionEncoderDecoderModel, TrOCRProcessor
            from peft import PeftModel
        except ImportError:
            return {"status": "error", "reason": "Missing dependencies"}

        # Load model
        base_model = VisionEncoderDecoderModel.from_pretrained(
            self.model_name, cache_dir=self.cache_dir
        )
        model = PeftModel.from_pretrained(base_model, model_path)
        model.to(self.device)
        model.eval()

        processor = TrOCRProcessor.from_pretrained(model_path)

        # Load test data
        test_data = self._load_jsonl(test_jsonl, images_dir)
        if not test_data:
            return {"status": "error", "reason": "No valid test samples"}

        predictions = []
        references = []

        with torch.no_grad():
            for rec in test_data:
                pixel_values = processor(images=rec["image"], return_tensors="pt").pixel_values.to(self.device)
                generated = model.generate(pixel_values)
                pred_text = processor.tokenizer.decode(generated[0], skip_special_tokens=True)
                predictions.append(pred_text)
                references.append(rec["text"])

        # Compute metrics
        try:
            import jiwer
            wer = jiwer.wer(references, predictions)
            cer = jiwer.cer(references, predictions)
        except ImportError:
            # Manual CER computation
            cer = self._manual_cer(references, predictions)
            wer = 0.0

        return {
            "status": "success",
            "test_samples": len(test_data),
            "wer": round(wer, 4),
            "cer": round(cer, 4),
            "model_path": model_path,
        }

    @staticmethod
    def _manual_cer(references: List[str], predictions: List[str]) -> float:
        """Simple Character Error Rate computation."""
        total_chars = 0
        total_errors = 0
        for ref, pred in zip(references, predictions):
            total_chars += len(ref)
            # Levenshtein distance
            m, n = len(ref), len(pred)
            dp = list(range(n + 1))
            for i in range(1, m + 1):
                prev = dp[0]
                dp[0] = i
                for j in range(1, n + 1):
                    temp = dp[j]
                    if ref[i - 1] == pred[j - 1]:
                        dp[j] = prev
                    else:
                        dp[j] = 1 + min(prev, dp[j], dp[j - 1])
                    prev = temp
            total_errors += dp[n]
        return total_errors / max(total_chars, 1)
