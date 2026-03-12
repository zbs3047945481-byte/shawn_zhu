from torch.utils.data import DataLoader
import torch.nn.functional as F
import time
import numpy as np
import torch.nn as nn
import torch
import copy
from src.models.feature_split import FeatureSplitModule
criterion = F.cross_entropy
mse_loss = nn.MSELoss()


class BaseClient():
    def __init__(self, options, id, local_dataset, model, optimizer, ):
        self.options = options
        self.id = id
        self.local_dataset = local_dataset
        self.model = model
        # 如果请求使用 GPU 但 CUDA 不可用，则使用 CPU
        self.gpu = options['gpu'] and torch.cuda.is_available()
        self.optimizer = optimizer

        # FedFed plugin: optional feature split module (local only, not aggregated)
        self.use_fedfed_plugin = options.get('use_fedfed_plugin', False)
        self.feature_split_module = None
        self.local_optimizer = None
        self.global_prototypes = None  # set by server before local_train
        if self.use_fedfed_plugin:
            fd = options.get('fedfed_feature_dim', 512)
            sd = options.get('fedfed_sensitive_dim', 64)
            self.feature_split_module = FeatureSplitModule(fd, sd)
            if self.gpu:
                self.feature_split_module.cuda()
            # Local optimizer includes model + feature_split for plugin training
            self.local_optimizer = torch.optim.Adam(
                list(self.model.parameters()) + list(self.feature_split_module.parameters()),
                lr=options.get('lr', 0.001)
            )

    def set_global_prototypes(self, global_prototypes):
        """Set global prototypes from server for prototype distillation."""
        self.global_prototypes = global_prototypes

    def set_global_sensitive_feature(self, global_sensitive_feature):
        """Backward-compatible alias for the old single-vector distillation target."""
        self.set_global_prototypes(global_sensitive_feature)

    def set_learning_rate(self, learning_rate):
        for group in self.optimizer.param_groups:
            group['lr'] = learning_rate
        if self.local_optimizer is not None:
            for group in self.local_optimizer.param_groups:
                group['lr'] = learning_rate

    def get_model_parameters(self):
        state_dict = self.model.state_dict()
        return state_dict

    def set_model_parameters(self, model_parameters_dict):
        state_dict = self.model.state_dict()
        for key, value in state_dict.items():
            state_dict[key] = model_parameters_dict[key]
        self.model.load_state_dict(state_dict)

    def local_train(self, ):
        begin_time = time.time()
        local_model_paras, return_dict, aux = self.local_update(self.local_dataset, self.options, )
        end_time = time.time()
        stats = {'id': self.id, "time": round(end_time - begin_time, 2)}
        stats.update(return_dict)
        # Update structure: weights (FedAvg) + num_samples + optional aux (FedFed)
        update = {"weights": local_model_paras, "num_samples": len(self.local_dataset), "aux": aux}
        return update, stats

    def _clip_and_noise_z_s(self, z_s, clip_norm, noise_sigma):
        """L2 clip (scale down if ||z_s|| > clip_norm) and add Gaussian noise (engineering-level privacy)."""
        if clip_norm is not None and clip_norm > 0:
            norm = z_s.norm(dim=-1, keepdim=True).clamp(min=1e-8)
            scale = torch.clamp(clip_norm / norm, max=1.0)  # scale down only when norm > clip_norm
            z_s = z_s * scale
        if noise_sigma is not None and noise_sigma > 0:
            z_s = z_s + noise_sigma * torch.randn_like(z_s, device=z_s.device)
        return z_s

    def _compute_prototype_distill_loss(self, z_s, y):
        if not self.global_prototypes:
            return None

        prototype_losses = []
        for label in y.unique():
            class_id = int(label.item())
            if class_id not in self.global_prototypes:
                continue
            class_mask = (y == label)
            local_proto = z_s[class_mask].mean(dim=0, keepdim=True)
            target_proto = self.global_prototypes[class_id].to(z_s.device).unsqueeze(0)
            prototype_losses.append(mse_loss(local_proto, target_proto))

        if not prototype_losses:
            return None
        return torch.stack(prototype_losses).mean()

    def local_update(self, local_dataset, options, ):
        use_plugin = self.use_fedfed_plugin
        optimizer = self.local_optimizer if use_plugin else self.optimizer

        localTrainDataLoader = DataLoader(local_dataset, batch_size=options['batch_size'], shuffle=True)
        self.model.train()
        if use_plugin and self.feature_split_module is not None:
            self.feature_split_module.train()

        train_loss = train_acc = train_total = 0
        prototype_sums = {}
        prototype_counts = {}

        for epoch in range(options['local_epoch']):
            train_loss = train_acc = train_total = 0
            for X, y in localTrainDataLoader:
                if self.gpu:
                    X, y = X.cuda(), y.cuda()
                optimizer.zero_grad()
                if use_plugin and self.feature_split_module is not None:
                    pred, h = self.model(X, return_feature=True)
                    z_s, z_r = self.feature_split_module(h)
                    loss_cls = criterion(pred, y)
                    loss = loss_cls
                    loss_distill = self._compute_prototype_distill_loss(z_s, y)
                    if loss_distill is not None:
                        lambda_d = options.get('fedfed_lambda_distill', 1.0)
                        loss = loss_cls + lambda_d * loss_distill
                    loss.backward()
                    optimizer.step()
                    with torch.no_grad():
                        for label in y.unique():
                            class_id = int(label.item())
                            class_mask = (y == label)
                            class_feature_sum = z_s[class_mask].detach().sum(dim=0)
                            class_count = int(class_mask.sum().item())
                            if class_id not in prototype_sums:
                                prototype_sums[class_id] = class_feature_sum
                                prototype_counts[class_id] = class_count
                            else:
                                prototype_sums[class_id] += class_feature_sum
                                prototype_counts[class_id] += class_count
                else:
                    pred = self.model(X)
                    loss = criterion(pred, y)
                    loss.backward()
                    optimizer.step()

                _, predicted = torch.max(pred, 1)
                correct = predicted.eq(y).sum().item()
                target_size = y.size(0)
                train_loss += loss.item() * y.size(0)
                train_acc += correct
                train_total += target_size

        local_model_paras = copy.deepcopy(self.get_model_parameters())
        return_dict = {"id": self.id,
                       "loss": train_loss / train_total,
                       "acc": train_acc / train_total}

        aux = None
        if use_plugin and self.feature_split_module is not None and prototype_sums:
            with torch.no_grad():
                clip_norm = options.get('fedfed_clip_norm', 1.0)
                noise_sigma = options.get('fedfed_noise_sigma', 0.1)
                local_prototypes = {}
                for class_id, feature_sum in prototype_sums.items():
                    prototype = (feature_sum / prototype_counts[class_id]).unsqueeze(0)
                    prototype = self._clip_and_noise_z_s(prototype, clip_norm, noise_sigma).squeeze(0)
                    local_prototypes[class_id] = {
                        "prototype": prototype.cpu(),
                        "count": prototype_counts[class_id],
                    }
                aux = {"prototypes": local_prototypes}

        return local_model_paras, return_dict, aux
