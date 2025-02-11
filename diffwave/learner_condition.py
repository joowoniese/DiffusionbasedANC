# Copyright 2020 LMNT, Inc. All Rights Reserved.
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.
# ==============================================================================

import numpy as np
import os
import torch
import torch.nn as nn
import csv

from torch.nn.parallel import DistributedDataParallel
from torch.utils.tensorboard import SummaryWriter
from tqdm import tqdm

from diffwave.dataset import from_path, from_gtzan
from diffwave.model import DiffWave
from diffwave.params import AttrDict


def _nested_map(struct, map_fn):
    if isinstance(struct, tuple):
        return tuple(_nested_map(x, map_fn) for x in struct)
    if isinstance(struct, list):
        return [_nested_map(x, map_fn) for x in struct]
    if isinstance(struct, dict):
        return {k: _nested_map(v, map_fn) for k, v in struct.items()}
    return map_fn(struct)


class DiffWaveLearner:
    def __init__(self, model_dir, model, dataset, optimizer, params, *args, **kwargs):
        os.makedirs(model_dir, exist_ok=True)
        self.model_dir = model_dir
        self.model = model
        self.dataset = dataset
        self.optimizer = optimizer
        self.params = params
        self.autocast = torch.amp.autocast('cuda', enabled=kwargs.get('fp16', False))
        self.scaler = torch.amp.GradScaler('cuda', enabled=kwargs.get('fp16', False))
        self.step = 0
        self.is_master = True

        beta = np.array(self.params.noise_schedule)
        noise_level = np.cumprod(1 - beta)
        self.noise_level = torch.tensor(noise_level.astype(np.float32))
        # Loss 재정의
        self.loss_fn = nn.L1Loss()
        self.summary_writer = None

    def state_dict(self):
        if hasattr(self.model, 'module') and isinstance(self.model.module, nn.Module):
            model_state = self.model.module.state_dict()
        else:
            model_state = self.model.state_dict()
        return {
            'step': self.step,
            'model': {k: v.cpu() if isinstance(v, torch.Tensor) else v for k, v in model_state.items()},
            'optimizer': {k: v.cpu() if isinstance(v, torch.Tensor) else v for k, v in
                          self.optimizer.state_dict().items()},
            'params': dict(self.params),
            'scaler': self.scaler.state_dict(),
        }

    def load_state_dict(self, state_dict):
        if hasattr(self.model, 'module') and isinstance(self.model.module, nn.Module):
            self.model.module.load_state_dict(state_dict['model'])
        else:
            self.model.load_state_dict(state_dict['model'])
        self.optimizer.load_state_dict(state_dict['optimizer'])
        self.scaler.load_state_dict(state_dict['scaler'])
        self.step = state_dict['step']

    def save_to_checkpoint(self, filename='weights'):
        save_basename = f'{filename}-{self.step}.pt'
        save_name = f'{self.model_dir}/{save_basename}'
        link_name = f'{self.model_dir}/{filename}.pt'
        torch.save(self.state_dict(), save_name)
        if os.name == 'nt':
            torch.save(self.state_dict(), link_name)
        else:
            if os.path.islink(link_name):
                os.unlink(link_name)
            os.symlink(save_basename, link_name)

    def restore_from_checkpoint(self, filename='weights'):
        try:
            checkpoint = torch.load(f'{self.model_dir}/{filename}.pt', weights_only=True)
            print(f"{self.model_dir}/{filename}.pt Loaded...")
            self.load_state_dict(checkpoint)
            print(f"[DEBUG] Restored checkpoint step: {self.step}")
            return True
        except FileNotFoundError:
            print(f"[WARNING] Checkpoint {filename}.pt not found.")
            return False

    def train(self, max_steps=None):
        device = next(self.model.parameters()).device
        while True:
            for features in tqdm(self.dataset,
                                 desc=f'Epoch {self.step // len(self.dataset)}') if self.is_master else self.dataset:
                if max_steps is not None and self.step >= max_steps:
                    return
                features = _nested_map(features, lambda x: x.to(device) if isinstance(x, torch.Tensor) else x)
                loss = self.train_step(features)
                if torch.isnan(loss).any():
                    raise RuntimeError(f'Detected NaN loss at step {self.step}.')
                if self.is_master:
                    if self.step % 50 == 0:
                        self._write_summary(self.step, features, loss)
                    if self.step % len(self.dataset) == 0:
                        self.save_to_checkpoint()
                self.step += 1

    def train_step(self, features):
        for param in self.model.parameters():
            param.grad = None

        audio = features['audio']  # Input 데이터
        target = features['target']  # 우리가 복원하고 싶은 Target 데이터 (Condition 역할)

        N, T = audio.shape
        device = audio.device
        self.noise_level = self.noise_level.to(device)

        with self.autocast:
            # Diffusion step t를 랜덤 샘플링
            t = torch.randint(0, len(self.params.noise_schedule), [N], device=audio.device)
            noise_scale = self.noise_level[t].unsqueeze(1)
            noise_scale_sqrt = noise_scale ** 0.5
            noise = torch.randn_like(audio)

            # Noisy Audio 생성
            noisy_audio = noise_scale_sqrt * audio + (1.0 - noise_scale) ** 0.5 * noise

            # 🔹 기존 spectrogram을 target으로 변경
            predicted = self.model(noisy_audio, t, target)

            # 🔹 Loss를 target을 직접 예측하는 방식으로 변경
            loss = self.loss_fn(target, predicted.squeeze(1))

        # 기존 학습 과정 유지
        self.scaler.scale(loss).backward()
        self.scaler.unscale_(self.optimizer)
        self.grad_norm = nn.utils.clip_grad_norm_(self.model.parameters(), self.params.max_grad_norm or 1e9)
        self.scaler.step(self.optimizer)
        self.scaler.update()
        return loss

    def _write_summary(self, step, features, loss):
        try:
            # SummaryWriter ??? ??
            if self.summary_writer is None:
                print(f"[DEBUG] Initializing SummaryWriter at step {step}")
                self.summary_writer = SummaryWriter("/hdd_ext/hdd3/joowoniese/diffwave4/event_logs/", purge_step=step)

            writer = self.summary_writer

            # ?? ? ?? ? ?? ??
            writer.add_scalar('train/loss', loss, step)
            print(f"[DEBUG] train/loss recorded at step {step}: {loss:.6f}")  # Loss ??

            # ????? ?? ?? ? ??
            writer.add_scalar('train/grad_norm', self.grad_norm, step)
            print(f"[DEBUG] train/grad_norm recorded at step {step}: {self.grad_norm:.6f}")  # Grad Norm ??

            # ??? ??
            if 'audio' in features:
                writer.add_audio('feature/audio', features['audio'][0], step, sample_rate=self.params.sample_rate)
                print(f"[DEBUG] feature/audio recorded at step {step}")

            # ?????? ??
            if not self.params.unconditional and 'spectrogram' in features:
                writer.add_image('feature/spectrogram', torch.flip(features['spectrogram'][:1], [1]), step)
                print(f"[DEBUG] feature/spectrogram recorded at step {step}")

            # ?? ??
            writer.flush()
            print(f"[DEBUG] SummaryWriter flushed at step {step}")

            # CSV ??? ??? ??
            loss_log_file = os.path.join("/hdd_ext/hdd3/joowoniese/diffwave4/event_logs/", 'loss_log.csv')
            if not os.path.exists(loss_log_file):
                # CSV ?? ??? (?? ??)
                with open(loss_log_file, 'w', newline='') as file:
                    csv_writer = csv.writer(file)
                    csv_writer.writerow(['step', 'loss', 'grad_norm'])  # ?? ??

            with open(loss_log_file, 'a', newline='') as file:
                csv_writer = csv.writer(file)
                csv_writer.writerow([step, loss.item(), self.grad_norm])
                print(f"[DEBUG] Loss and grad_norm saved to CSV at step {step}")

        except Exception as e:
            print(f"[ERROR] Failed to write summary at step {step}: {e}")


def _train_impl(replica_id, model, dataset, args, params):
    torch.backends.cudnn.benchmark = True
    opt = torch.optim.Adam(model.parameters(), lr=params.learning_rate)

    learner = DiffWaveLearner(args.model_dir, model, dataset, opt, params, fp16=args.fp16)
    learner.is_master = (replica_id == 0)
    learner.restore_from_checkpoint()
    learner.train(max_steps=args.max_steps)


def train(args, params):
    if args.data_dirs[0] == 'gtzan':
        dataset = from_gtzan(params)
    else:
        dataset = from_path(args.data_dirs, params)
    model = DiffWave(params).cuda()
    _train_impl(0, model, dataset, args, params)


def train_distributed(replica_id, replica_count, port, args, params):
    os.environ['MASTER_ADDR'] = 'localhost'
    os.environ['MASTER_PORT'] = str(port)
    torch.distributed.init_process_group('nccl', rank=replica_id, world_size=replica_count)
    if args.data_dirs[0] == 'gtzan':
        dataset = from_gtzan(params, is_distributed=True)
    else:
        dataset = from_path(args.data_dirs, params, is_distributed=True)
    device = torch.device('cuda', replica_id)
    torch.cuda.set_device(device)
    model = DiffWave(params).to(device)
    model = DistributedDataParallel(model, device_ids=[replica_id])
    _train_impl(replica_id, model, dataset, args, params)