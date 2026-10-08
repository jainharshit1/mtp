"""Exponential Moving Average for LoRA parameters only."""

import copy
import torch
import torch.nn as nn


class LoRAModelEma:
    """EMA tracker for LoRA (trainable) parameters only.

    Maintains a shadow copy of only the trainable params, saving VRAM
    compared to a full model copy (~50MB vs ~700MB).
    """

    def __init__(self, model: nn.Module, decay: float = 0.9997):
        self.decay = decay
        # Store shadow copies of trainable parameters
        self.shadow = {}
        self.backup = {}
        for name, param in model.named_parameters():
            if param.requires_grad:
                self.shadow[name] = param.data.clone()

    @torch.no_grad()
    def update(self, model: nn.Module):
        for name, param in model.named_parameters():
            if param.requires_grad and name in self.shadow:
                self.shadow[name].mul_(self.decay).add_(
                    param.data, alpha=1.0 - self.decay
                )

    def apply_shadow(self, model: nn.Module):
        """Swap model params with EMA shadow (for evaluation)."""
        self.backup = {}
        for name, param in model.named_parameters():
            if param.requires_grad and name in self.shadow:
                self.backup[name] = param.data.clone()
                param.data.copy_(self.shadow[name])

    def restore(self, model: nn.Module):
        """Restore model params from backup (after evaluation)."""
        for name, param in model.named_parameters():
            if param.requires_grad and name in self.backup:
                param.data.copy_(self.backup[name])
        self.backup = {}

    def state_dict(self):
        return {"shadow": self.shadow, "decay": self.decay}

    def load_state_dict(self, state_dict):
        self.shadow = state_dict["shadow"]
        self.decay = state_dict["decay"]
