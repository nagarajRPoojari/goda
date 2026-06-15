from typing import Generator, Tuple

import torch

from mint.data.dataloader import DistributedDataloader
from mint.tokenizer import Tokenizer
from mint.data.datasets.base import SFTDataset
from mint.utils.device import Device
from mint.utils.logger import logger
from goda.config import Config

class DistributedSFTDataloader(DistributedDataloader):
    def __init__(self, device: Device, config: Config, tokenizer: Tokenizer, datasets: list[SFTDataset], shuffle: bool = True) -> None:
        super().__init__(
            device=device,
            data_dir="",
            batch_size=config.batch_size,
            seq_len=config.seq_length,
            tokenizer=tokenizer
        )
        
        self.datasets = datasets
        self.max_tokens = config.seq_length
        self.shuffle = shuffle
        
        proc_info = device.process_info()
        self.rank = proc_info["rank"]
        self.world_size = proc_info["world_size"]
        
        self.dataset_indices = self._build_dataset_indices()
        self.rank_indices = self._partition_for_rank()
        
        use_cuda = device.is_cuda
        self.cpu_buffer = torch.empty(2 * self.B * self.T, dtype=torch.long, pin_memory=use_cuda)
        self.gpu_buffer = torch.empty(2 * self.B * self.T, dtype=torch.long, device=device.device)
        
        self.cpu_inputs = self.cpu_buffer[:self.B * self.T].view(self.B, self.T)
        self.cpu_targets = self.cpu_buffer[self.B * self.T:].view(self.B, self.T)
        self.cpu_mask = torch.zeros(self.B, self.T, dtype=torch.long, pin_memory=use_cuda)
        
        self.inputs = self.gpu_buffer[:self.B * self.T].view(self.B, self.T)
        self.targets = self.gpu_buffer[self.B * self.T:].view(self.B, self.T)
        self.mask = torch.zeros(self.B, self.T, dtype=torch.long, device=device.device)
    
    def _build_dataset_indices(self) -> list:
        import random
        indices = []
        for ds_idx, ds in enumerate(self.datasets):
            indices.extend([(ds_idx, i) for i in range(len(ds))])
        if self.shuffle:
            random.Random(42).shuffle(indices)
        return indices
    
    def _partition_for_rank(self) -> list:
        return [idx for i, idx in enumerate(self.dataset_indices) if i % self.world_size == self.rank]
    
    def batch_loader(self, split: str = "train", resume_state: dict | None = None) -> Generator[Tuple[torch.Tensor, torch.Tensor, torch.Tensor], None, None]:
        idx = 0
        total = len(self.rank_indices)
        
        while True:
            for batch_idx in range(self.B):
                ds_idx, example_idx = self.rank_indices[idx % total]
                idx += 1
                
                conversation = self.datasets[ds_idx][example_idx]
                ids, mask = self.tokenizer.render_conversation(conversation, self.max_tokens)
                
                seq_len = len(ids)
                if seq_len <= self.T:
                    ids = ids + [self.tokenizer.pad_token] * (self.T + 1 - seq_len)
                    mask = mask + [0] * (self.T + 1 - seq_len)
                else:
                    ids = ids[:self.T + 1]
                    mask = mask[:self.T + 1]
                
                self.cpu_inputs[batch_idx] = torch.tensor(ids[:-1], dtype=torch.long)
                self.cpu_targets[batch_idx] = torch.tensor(ids[1:], dtype=torch.long)
                self.cpu_mask[batch_idx] = torch.tensor(mask[1:], dtype=torch.long)
            
            self.gpu_buffer.copy_(self.cpu_buffer, non_blocking=self.device.is_cuda)
            self.mask.copy_(self.cpu_mask, non_blocking=self.device.is_cuda)
            
            yield self.inputs, self.targets, self.mask

    def get_state(self) -> dict:
        return {}
    
    def set_state(self, state: dict) -> None:
        pass

    def sample(self, num_samples: int = 1):
        import random
        samples = []
        
        for _ in range(num_samples):
            ds_idx = random.randint(0, len(self.datasets) - 1)
            example_idx = random.randint(0, len(self.datasets[ds_idx]) - 1)
            
            conversation = self.datasets[ds_idx][example_idx]
            ids, mask = self.tokenizer.render_conversation(conversation, self.max_tokens)
            
            if len(ids) > self.T:
                ids = ids[:self.T]
                mask = mask[:self.T]
            
            input_tokens = torch.tensor(ids[:-1] if len(ids) > 1 else ids, dtype=torch.long)
            target_tokens = torch.tensor(ids[1:] if len(ids) > 1 else ids, dtype=torch.long)
            
            input_str = self.tokenizer.decode(input_tokens.unsqueeze(0))[0]
            target_str = self.tokenizer.decode(target_tokens.unsqueeze(0))[0]
            
            samples.append({
                'input_tokens': input_tokens,
                'target_tokens': target_tokens,
                'input_str': input_str,
                'target_str': target_str
            })
        
        return samples