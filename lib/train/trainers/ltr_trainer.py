import os
from collections import OrderedDict
from lib.train.trainers import BaseTrainer
from lib.train.admin import AverageMeter, StatValue
from lib.train.admin import TensorboardWriter
import torch
import time
from torch.utils.data.distributed import DistributedSampler
from torch.cuda.amp import autocast
from torch.cuda.amp import GradScaler
import lib.utils.misc as misc


class LTRTrainer(BaseTrainer):
    def __init__(self, actor, loaders, optimizer, settings, lr_scheduler=None, use_amp=False):
        """
        args:
            actor - The actor for training the network
            loaders - list of dataset loaders, e.g. [train_loader, val_loader]. In each epoch, the trainer runs one
                        epoch for each loader.
            optimizer - The optimizer used for training, e.g. Adam
            settings - Training settings
            lr_scheduler - Learning rate scheduler
        """
        super().__init__(actor, loaders, optimizer, settings, lr_scheduler)
        self._set_default_settings()

        # Initialize statistics variables
        self.stats = OrderedDict({loader.name: None for loader in self.loaders})

        # Initialize tensorboard
        if settings.local_rank in [-1, 0]:
            tensorboard_writer_dir = os.path.join(self.settings.env.tensorboard_dir, self.settings.project_path)
            if not os.path.exists(tensorboard_writer_dir):
                os.makedirs(tensorboard_writer_dir)
            self.tensorboard_writer = TensorboardWriter(tensorboard_writer_dir, [l.name for l in loaders])

        self.move_data_to_gpu = getattr(settings, 'move_data_to_gpu', True)
        self.settings = settings
        self.use_amp = use_amp
        if use_amp:
            self.scaler = GradScaler()

    def _move_dict_to_device(self, data, device):
        """Recursively move tensors in dict to specified device"""
        if isinstance(data, dict):
            return {key: self._move_dict_to_device(value, device) for key, value in data.items()}
        elif isinstance(data, list):
            return [self._move_dict_to_device(item, device) for item in data]
        elif isinstance(data, torch.Tensor):
            return data.to(device)
        else:
            return data

    def _set_default_settings(self):
        # Dict of all default values
        default = {'print_interval': 10,
                   'print_stats': None,
                   'description': ''}

        for param, default_value in default.items():
            if getattr(self.settings, param, None) is None:
                setattr(self.settings, param, default_value)

    def cycle_dataset(self, loader):
        """Do a cycle of training or validation."""

        self.actor.train(loader.training)
        torch.set_grad_enabled(loader.training)

        # '''fix the normalization layers in the pretrained seqtrackv1 model'''
        # if self.settings.fix_norm:
        #     self.actor.fix_norms()

        self._init_timing()
        print("Current Epoch: ", self.epoch)
        # print(loader.training)

        if loader.training:
            self.optimizer.zero_grad(set_to_none=True)

        for i, data in enumerate(loader, 1):
            if data is None or len(data) == 0:
                print(f"Warning: Empty batch at iteration {i}")
                continue

            if self.move_data_to_gpu:
                # Move data to GPU
                data = self._move_dict_to_device(data, self.device)

            data['epoch'] = self.epoch
            data['settings'] = self.settings
            # forward pass
            if not self.use_amp:
                loss, stats = self.actor(data)
            else:
                with autocast():
                    loss, stats = self.actor(data)

            # backward pass and update weights
            if loader.training:
                loss = loss / self.settings.accum_iter
                if not self.use_amp:
                    loss.backward()
                    if i % self.settings.accum_iter == 0 or i == len(loader):
                        if self.settings.grad_clip_norm > 0:
                            torch.nn.utils.clip_grad_norm_(self.actor.net.parameters(), self.settings.grad_clip_norm)
                        self.optimizer.step()
                        self.optimizer.zero_grad(set_to_none=True)
                else:
                    self.scaler.scale(loss).backward()
                    if i % self.settings.accum_iter == 0 or i == len(loader):
                        self.scaler.step(self.optimizer)
                        self.scaler.update()
                        self.optimizer.zero_grad(set_to_none=True)

            if i % self.settings.print_interval == 0 or i == loader.__len__():
                torch.cuda.synchronize()

            # update statistics
            batch_size = data['template_images'].shape[loader.stack_dim]
            self._update_stats(stats, batch_size, loader)

            # print statistics
            self._print_stats(i, loader, batch_size)


    def train_epoch(self):
        """Do one epoch for each loader."""
        # LAST-ViT: 检查是否需要解冻基础编码器
        self._check_and_unfreeze_encoder()
        
        for loader in self.loaders:
            if self.epoch % loader.epoch_interval == 0:
                # 2021.1.10 Set epoch
                if isinstance(loader.sampler, DistributedSampler):
                    loader.sampler.set_epoch(self.epoch)
                self.cycle_dataset(loader)

        self._stats_new_epoch()
        if self.settings.local_rank in [-1, 0]:
            self._write_tensorboard()
    
    def _check_and_unfreeze_encoder(self):
        """检查并解冻基础编码器 - LAST-ViT专用"""
        freeze_base_epochs = getattr(self.settings, 'FREEZE_BASE_EPOCHS', 0)
        
        if freeze_base_epochs > 0 and self.epoch == freeze_base_epochs + 1:
            # 到达解冻epoch
            print(f"\n{'='*60}")
            print(f"Epoch {self.epoch}: Unfreezing base encoder!")
            print(f"{'='*60}\n")
            
            # 解冻基础编码器参数
            if hasattr(self.actor.net, 'encoder'):
                encoder = self.actor.net.encoder
                
                # 解冻所有参数
                for param in encoder.parameters():
                    param.requires_grad = True
                
                # 重新初始化优化器（重要！）
                self._reinitialize_optimizer()
                
                print("Base encoder unfrozen and optimizer reinitialized.")
    
    def _reinitialize_optimizer(self):
        """重新初始化优化器以包含新解冻的参数"""
        import torch.optim as optim
        
        # 获取当前学习率
        current_lr = self.optimizer.param_groups[0]['lr']
        weight_decay = self.optimizer.param_groups[0].get('weight_decay', 0.0001)
        
        # 重新创建优化器
        self.optimizer = optim.AdamW(
            self.actor.net.parameters(),
            lr=current_lr,
            weight_decay=weight_decay
        )
        
        print(f"Optimizer reinitialized with lr={current_lr}")

    def _init_timing(self):
        self.num_frames = 0
        self.start_time = time.time()
        self.prev_time = self.start_time

    def _update_stats(self, new_stats: OrderedDict, batch_size, loader):
        # Initialize stats if not initialized yet
        if loader.name not in self.stats.keys() or self.stats[loader.name] is None:
            self.stats[loader.name] = OrderedDict({name: AverageMeter() for name in new_stats.keys()})

        for name, val in new_stats.items():
            if name not in self.stats[loader.name].keys():
                self.stats[loader.name][name] = AverageMeter()
            self.stats[loader.name][name].update(val, batch_size)

    def _print_stats(self, i, loader, batch_size):
        self.num_frames += batch_size
        current_time = time.time()
        batch_fps = batch_size / (current_time - self.prev_time)
        average_fps = self.num_frames / (current_time - self.start_time)
        self.prev_time = current_time
        if i % self.settings.print_interval == 0 or i == loader.__len__():
            print_str = '[%s: %d, %d / %d] ' % (loader.name, self.epoch, i, loader.__len__())
            print_str += 'FPS: %.1f (%.1f)  ,  ' % (average_fps, batch_fps)
            for name, val in self.stats[loader.name].items():
                if (self.settings.print_stats is None or name in self.settings.print_stats):
                    if hasattr(val, 'avg'):
                        print_str += '%s: %.5f  ,  ' % (name, val.avg)

            print(print_str[:-5])
            log_str = print_str[:-5] + '\n'
            if misc.is_main_process():
                # print(self.settings.log_file)
                with open(self.settings.log_file, 'a') as f:
                    f.write(log_str)

    def _stats_new_epoch(self):
        # Record learning rate
        for loader in self.loaders:
            if loader.training:
                try:
                    lr_list = self.lr_scheduler.get_lr()
                except:
                    lr_list = self.lr_scheduler._get_lr(self.epoch)
                for i, lr in enumerate(lr_list):
                    var_name = 'LearningRate/group{}'.format(i)
                    if var_name not in self.stats[loader.name].keys():
                        self.stats[loader.name][var_name] = StatValue()
                    self.stats[loader.name][var_name].update(lr)

        for loader_stats in self.stats.values():
            if loader_stats is None:
                continue
            for stat_value in loader_stats.values():
                if hasattr(stat_value, 'new_epoch'):
                    stat_value.new_epoch()

    def _write_tensorboard(self):
        if self.epoch == 1:
            self.tensorboard_writer.write_info(self.settings.script_name, self.settings.description)

        self.tensorboard_writer.write_epoch(self.stats, self.epoch)
