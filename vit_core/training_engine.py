"""Training loops shared by all transfer-learning experiments."""

from pathlib import Path

import torch
from torch import nn
from torch.optim import Optimizer
from torch.utils.data import DataLoader

from vit_core.checkpoint import (
    load_trainable_checkpoint,
    save_trainable_checkpoint,
)
from vit_core.evaluation import test


def train_one_epoch(
    model: nn.Module,
    dataloader: DataLoader,
    optimizer: Optimizer,
    criterion: nn.Module,
    device: torch.device,
) -> dict[str, float]:
    """训练一个epoch，返回按样本统计的平均loss和accuracy。"""
    model.train()

    total_loss = 0.0
    total_correct = 0
    total_samples = 0

    use_bf16 = device.type == "cuda" and torch.cuda.is_bf16_supported()

    for images, labels in dataloader:
        images = images.to(device, non_blocking=True)
        labels = labels.to(device, non_blocking=True)

        optimizer.zero_grad(set_to_none=True)

        with torch.autocast(
            device_type=device.type,
            dtype=torch.bfloat16,
            enabled=use_bf16,
        ):
            logits = model(images)
            loss = criterion(logits, labels)

        loss.backward()
        optimizer.step()

        batch_size = labels.size(0)
        total_loss += loss.detach().item() * batch_size
        total_correct += (logits.argmax(dim=1) == labels).sum().item()
        total_samples += batch_size

    if total_samples == 0:
        raise ValueError("训练DataLoader中没有样本。")

    return {
        "loss": total_loss / total_samples,
        "accuracy": total_correct / total_samples,
    }


def train(
    model: nn.Module,
    train_loader: DataLoader,
    val_loader: DataLoader,
    optimizer: Optimizer,
    criterion: nn.Module,
    device: torch.device,
    num_epochs: int,
    checkpoint_path: str | Path,
) -> list[dict[str, float | int]]:
    """训练多个epoch，并恢复验证准确率最高的可训练参数。"""
    model.to(device)
    checkpoint_path = Path(checkpoint_path)
    checkpoint_path.parent.mkdir(parents=True, exist_ok=True)

    history: list[dict[str, float | int]] = []
    best_val_accuracy = -1.0

    for epoch in range(1, num_epochs + 1):
        train_metrics = train_one_epoch(
            model=model,
            dataloader=train_loader,
            optimizer=optimizer,
            criterion=criterion,
            device=device,
        )
        val_metrics = test(
            model=model,
            dataloader=val_loader,
            criterion=criterion,
            device=device,
        )

        epoch_metrics = {
            "epoch": epoch,
            "train_loss": train_metrics["loss"],
            "train_accuracy": train_metrics["accuracy"],
            "val_loss": val_metrics["loss"],
            "val_accuracy": val_metrics["accuracy"],
        }
        history.append(epoch_metrics)

        print(
            f"Epoch {epoch:02d}/{num_epochs:02d} | "
            f"train loss {train_metrics['loss']:.4f}, "
            f"train acc {train_metrics['accuracy']:.4f} | "
            f"val loss {val_metrics['loss']:.4f}, "
            f"val acc {val_metrics['accuracy']:.4f}"
        )

        if val_metrics["accuracy"] > best_val_accuracy:
            best_val_accuracy = float(val_metrics["accuracy"])
            save_trainable_checkpoint(
                model=model,
                checkpoint_path=checkpoint_path,
                epoch=epoch,
                val_accuracy=best_val_accuracy,
            )

    load_trainable_checkpoint(model, checkpoint_path)
    model.to(device)
    return history
