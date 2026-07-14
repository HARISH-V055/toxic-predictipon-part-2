"""
Evaluation Engine Module for EQ-KA-GCN

Provides the Evaluator class to execute model inference over test datasets,
evaluating key metrics like accuracy, balanced accuracy, recall, precision, F1,
Matthews Correlation Coefficient (MCC), ROC-AUC, and inference latency.
"""

import logging
import time
from typing import Any, Dict, Tuple
import numpy as np
import torch
import torch.nn as nn
from torch_geometric.loader import DataLoader
from sklearn.metrics import (
    accuracy_score,
    balanced_accuracy_score,
    classification_report,
    confusion_matrix,
    f1_score,
    matthews_corrcoef,
    precision_score,
    recall_score,
    roc_auc_score,
)

logger = logging.getLogger("EQ-KA-GCN.evaluation.evaluator")


class Evaluator:
    """
    Evaluates trained GCN models on testing datasets.
    Controls forward passes, prediction thresholding, performance metric calculations,
    and computational profiling.
    """

    def __init__(self, model: nn.Module, device: torch.device) -> None:
        """
        Initializes the model Evaluator.

        Args:
            model (nn.Module): GCN model instance to evaluate.
            device (torch.device): Computing device to use (CUDA or CPU).
        """
        self.model = model
        self.device = device

    def load_model(self, checkpoint_path: str) -> None:
        """
        Loads the best performing trained weights into the model.

        Args:
            checkpoint_path (str): File path to model state dict checkpoint (.pt).
        """
        logger.info(f"Loading GCN model state dict checkpoint from: {checkpoint_path}")
        try:
            state_dict = torch.load(checkpoint_path, map_location=self.device)
            self.model.load_state_dict(state_dict)
            logger.info("Successfully loaded GCN checkpoint.")
        except Exception as e:
            logger.error(f"Failed to load checkpoint from {checkpoint_path}: {str(e)}")
            raise e

    def evaluate(
        self, loader: DataLoader, threshold: float = 0.5
    ) -> Tuple[Dict[str, Any], np.ndarray, np.ndarray, np.ndarray]:
        """
        Runs model evaluation over the test dataset.

        Args:
            loader (DataLoader): DataLoader for testing graphs.
            threshold (float): Decision threshold for binary classification.

        Returns:
            Tuple[Dict[str, Any], np.ndarray, np.ndarray, np.ndarray]:
                - Dictionary containing all computed evaluation metrics.
                - Ground truth labels (y_true).
                - Class predictions (y_pred).
                - Toxicity probabilities (y_prob).
        """
        logger.info(f"Evaluating GCN model on test dataset (Decision threshold: {threshold})...")
        self.model.eval()

        all_targets = []
        all_probs = []

        total_samples = 0
        inference_start = time.time()

        with torch.no_grad():
            for batch in loader:
                batch_x = batch.x.to(self.device)
                batch_edge_index = batch.edge_index.to(self.device)
                batch_indicator = batch.batch.to(self.device)
                targets = batch.y.to(self.device).view(-1, 1).float()

                # Model forward pass (obtaining logits)
                logits = self.model(
                    x=batch_x,
                    edge_index=batch_edge_index,
                    batch=batch_indicator,
                    return_logits=True,
                )

                # Convert raw logits to probabilities
                probs = torch.sigmoid(logits)

                # Accumulate values
                all_targets.append(targets.cpu().numpy())
                all_probs.append(probs.cpu().numpy())
                total_samples += batch.num_graphs

        total_inference_time = time.time() - inference_start
        avg_inference_time_ms = (
            (total_inference_time / total_samples) * 1000 if total_samples > 0 else 0.0
        )
        logger.info(
            f"Inference complete. Processed {total_samples} graphs. "
            f"Average latency per sample: {avg_inference_time_ms:.3f} ms"
        )

        # Reshape and parse labels
        y_true = np.concatenate(all_targets, axis=0).flatten().astype(int)
        y_prob = np.concatenate(all_probs, axis=0).flatten()
        y_pred = (y_prob >= threshold).astype(int)

        # 1. Compute scikit-learn metrics
        acc = accuracy_score(y_true, y_pred)
        bal_acc = balanced_accuracy_score(y_true, y_pred)
        prec = precision_score(y_true, y_pred, zero_division=0)
        rec = recall_score(y_true, y_pred, zero_division=0)
        f1 = f1_score(y_true, y_pred, zero_division=0)
        mcc = matthews_corrcoef(y_true, y_pred)
        
        # ROC-AUC calculation (handling single-class edge cases)
        if len(np.unique(y_true)) > 1:
            auc = roc_auc_score(y_true, y_prob)
        else:
            logger.warning("Only one target class present in test dataset. ROC-AUC set to 0.5.")
            auc = 0.5

        # Confusion Matrix
        cm = confusion_matrix(y_true, y_pred).tolist()

        # Classification Report (dictionary form)
        class_report_dict = classification_report(
            y_true, y_pred, output_dict=True, zero_division=0
        )
        # Classification Report (string version for text export)
        class_report_str = classification_report(
            y_true, y_pred, zero_division=0
        )

        metrics = {
            "accuracy": float(acc),
            "balanced_accuracy": float(bal_acc),
            "precision": float(prec),
            "recall": float(rec),
            "f1_score": float(f1),
            "roc_auc": float(auc),
            "mcc": float(mcc),
            "confusion_matrix": cm,
            "classification_report_dict": class_report_dict,
            "classification_report_str": class_report_str,
            "inference_time_per_sample_ms": float(avg_inference_time_ms),
        }

        logger.info(f"Evaluation metrics computed successfully. Accuracy: {acc:.4f} | ROC-AUC: {auc:.4f}")
        return metrics, y_true, y_pred, y_prob
