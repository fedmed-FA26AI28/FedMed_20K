"""Local training loop for client models.

Performs forward and backward passes, updates model parameters,
and optionally tracks local validation metrics, learning rate reduction,
and early stopping.
"""

import time
import copy
import torch
import torch.nn as nn
from torch.optim.lr_scheduler import ReduceLROnPlateau


def train(
    model,
    train_loader,
    optimizer,
    epochs,
    device,
    val_loader=None,
    lr_patience: int = 3,
    lr_factor: float = 0.5,
    min_lr: float = 1e-6,
    early_stop_patience: int = 8,
):
    criterion = nn.CrossEntropyLoss()
    model.train()

    start_time = time.time()

    # 1. Initialize Learning Rate Scheduler
    # - factor: reduce LR by multiplicative factor when validation loss plateaus
    # - patience: epochs to wait before reducing LR
    # - min_lr: lower bound for learning rate
    scheduler = ReduceLROnPlateau(
        optimizer, mode='min', factor=lr_factor, patience=lr_patience, min_lr=min_lr
    )
    
    # 2. Early stopping state
    best_loss = float('inf')
    patience_counter = 0
    patience = early_stop_patience
    best_weights = None
    best_epoch = 0
    best_val_loss = None
    best_val_acc = None

    history = {
        "loss": [],
        "accuracy": []
    }

    if val_loader is not None:
        history["val_loss"] = []
        history["val_accuracy"] = []
    
    total = 0
    for epoch in range(epochs):
        model.train() 
        
        running_loss = 0.0
        correct = 0
        total = 0
        for images, labels in train_loader:
            images = images.to(device)
            labels = labels.view(-1).long().to(device)

            optimizer.zero_grad()
            outputs = model(images)
            loss = criterion(outputs, labels)
            loss.backward()
            optimizer.step()

            running_loss += loss.item() * images.size(0)
            _, predicted = torch.max(outputs.data, 1)
            total += labels.size(0)
            correct += (predicted == labels).sum().item()

        epoch_loss = running_loss / total
        epoch_accuracy = correct / total

        history['loss'].append(epoch_loss)
        history['accuracy'].append(epoch_accuracy)
        
        current_lr = optimizer.param_groups[0]['lr']
        print_str = f"Epoch [{epoch + 1}/{epochs}] (LR: {current_lr:.6f}) | Train Loss: {epoch_loss:.4f}, Train Acc: {epoch_accuracy:.4f}"

        if val_loader is not None:
            model.eval()
            val_loss = 0.0
            val_correct = 0
            val_total = 0
            with torch.no_grad():
                for val_images, val_labels in val_loader:
                    val_images = val_images.to(device)
                    val_labels = val_labels.view(-1).long().to(device)

                    val_outputs = model(val_images)
                    v_loss = criterion(val_outputs, val_labels)
                    val_loss += v_loss.item() * val_images.size(0)

                    _, val_predicted = torch.max(val_outputs.data, 1)
                    val_total += val_labels.size(0)
                    val_correct += (val_predicted == val_labels).sum().item()
            val_epoch_loss = val_loss / val_total
            val_epoch_accuracy = val_correct / val_total
            history['val_loss'].append(val_epoch_loss)  
            history['val_accuracy'].append(val_epoch_accuracy)

            print_str += f" | Val Loss: {val_epoch_loss:.4f}, Val Acc: {val_epoch_accuracy:.4f}"
            print(print_str)
            
            old_lr = optimizer.param_groups[0]['lr']
            scheduler.step(val_epoch_loss)
            new_lr = optimizer.param_groups[0]['lr']
            
            if new_lr < old_lr:
                print(f"   Val loss did not decrease, automatically reducing Learning Rate to {new_lr:.6f}")
                
            # --- Early stopping on validation loss ---
            if val_epoch_loss < best_loss:
                best_loss = val_epoch_loss
                patience_counter = 0
                best_weights = copy.deepcopy(model.state_dict())
                best_epoch = epoch + 1
                best_val_loss = val_epoch_loss
                best_val_acc = val_epoch_accuracy
            else:
                patience_counter += 1
                if patience_counter >= patience:
                    print(f"--- Early stopping triggered at Epoch {epoch + 1}! Val Loss did not decrease for {patience} consecutive epochs. ---")
                    break
        else:
            # If no validation set, display training metrics only
            print(print_str)
        
    training_time = time.time() - start_time
    if val_loader is not None and best_weights is not None:
        print("Reloading best weights for testing...")
        model.load_state_dict(best_weights)

    metrics = {
        "training_time": training_time,
        "final_loss": history['loss'][-1] if history['loss'] else 0.0,
        "final_accuracy": history['accuracy'][-1] if history['accuracy'] else 0.0,
        "num_samples": total,
        "history": history
    }
    if val_loader is not None and 'val_loss' in history and history['val_loss']:
        metrics["final_val_loss"] = history['val_loss'][-1]
        metrics["final_val_accuracy"] = history['val_accuracy'][-1]
        metrics["best_epoch"] = best_epoch
        metrics["best_val_loss"] = best_val_loss
        metrics["best_val_acc"] = best_val_acc
    return metrics