import argparse
import deepspeed

parser = argparse.ArgumentParser(description='sp')
parser.add_argument('--basepath', type=str, default='/home/lyh/weights/hf/llama31chat/8B/')
parser.add_argument('--trainpath', type=str,
                    default="/home/lyh/code/nlp/developing/vllmbase/vllm/gedata/l318b.jsonl")
parser.add_argument('--testpath', type=str,
                    default="/home/lyh/code/nlp/developing/vllmbase/vllm/gedata/0318.json")
parser.add_argument('--savedir', type=str, default='0')
parser.add_argument("--local_rank", type=int, default=-1, help="local_rank for distributed training on gpus")
parser = deepspeed.add_config_arguments(parser)
args = parser.parse_args()
import json
import re

deepspeed_config = args.deepspeed_config
with open(deepspeed_config) as f:
    ds_config = json.load(f)
train_config = {
    "bs": ds_config["train_micro_batch_size_per_gpu"],
    "num_epochs": 40,
    "num_workers": 2,
    "max_len": 2048,
    "config_path": "train/configs/qwen2.5vl_eagle3_config.json",
    "gradient_checkpointing": True
}

from safetensors import safe_open
from transformers import AutoModelForCausalLM, AutoTokenizer
import os
# os.environ["CUDA_VISIBLE_DEVICES"] = "0,1"
import torch
from cnets_vlm import padding

torch.backends.cuda.matmul.allow_tf32 = True
from accelerate.utils import set_seed

set_seed(0)
from train.model.cnets_eagle3 import Model
from train.model.configs import EConfig
from datasets import load_dataset
from dataclasses import dataclass, field
from typing import Any, Dict, List, Optional, Union

from torch import nn, optim
from torch.utils.data import Dataset, DataLoader, DistributedSampler
from tqdm import tqdm
# import accelerate
import numpy as np
from transformers import PreTrainedTokenizerBase, get_linear_schedule_with_warmup



def build_dataset_rank(
        tokenizer, datapath
):

    ds = load_dataset('json', data_files=datapath)
    ds = ds['train']
    ds = ds.shuffle(seed=42)
    ds1 = ds
    original_columns1 = ds1.column_names
    num_proc = 8

    def preprocess_function(examples):
        new_examples = {
            "attention_mask": [],
            "input_ids": [],
            "loss_mask": []
        }
        for i in range(len(examples['id'])):
            messages = [
                {"role": "system",
                 "content": "You are a helpful, respectful and honest assistant. Always answer as helpfully as possible, while being safe. Your answers should not include any harmful, unethical, racist, sexist, toxic, dangerous, or illegal content. Please ensure that your responses are socially unbiased and positive in nature.\n\nIf a question does not make any sense, or is not factually coherent, explain why instead of answering something not correct. If you don't know the answer to a question, please don't share false information."},
            ]
            convroles = ["user", "assistant"]
            roles = {"human": "user", "gpt": "assistant"}
            source = examples['conversations'][i]
            if not source:
                continue
            if roles.get(source[0]["from"]) != "user":
                source = source[1:]
            if not source:
                continue
            for j, sentence in enumerate(source):
                role = roles.get(sentence["from"], sentence["from"])
                if role != convroles[j % 2]:
                    break
                messages.append(
                    {"role": role, "content": sentence["value"]}
                )
            conversation = tokenizer.apply_chat_template(
                messages,
                tokenize=False,
                add_generation_prompt=False,
            )

            if not tokenizer.pad_token_id:
                tokenizer.pad_token_id = tokenizer.eos_token_id

            input_ids = tokenizer(
                conversation,
                return_tensors="pt",
                add_special_tokens=False,
            ).input_ids[0]
            # filtering out samples longer than max_len
            if len(input_ids) > train_config["max_len"]:
                continue
            loss_mask = torch.ones_like(input_ids)

            # Qwen2 chat template uses <|im_start|> and <|im_end|>
            sep_assistant = "<|im_start|>assistant\n"
            sep_end = "<|im_end|>"
            
            # Find assistant response regions and mask everything else
            loss_mask[:] = 0  # Start with all masked
            parts = conversation.split(sep_assistant)
            cur_pos = 0
            for pi, part in enumerate(parts):
                if pi == 0:
                    cur_pos += len(tokenizer(part + sep_assistant, add_special_tokens=False).input_ids)
                else:
                    if sep_end in part:
                        response = part.split(sep_end)[0]
                        response_ids = tokenizer(response, add_special_tokens=False).input_ids
                        resp_len = len(response_ids)
                        end_pos = min(cur_pos + resp_len, len(loss_mask))
                        loss_mask[cur_pos:end_pos] = 1
                    cur_pos += len(tokenizer(part + (sep_assistant if pi < len(parts) - 1 else ""), add_special_tokens=False).input_ids)

            attention_mask = torch.ones_like(loss_mask)

            new_examples["input_ids"].append(input_ids[None, :])
            new_examples["loss_mask"].append(loss_mask[None, :])
            new_examples["attention_mask"].append(attention_mask[None, :])

        return new_examples

    ds1 = ds1.map(
        preprocess_function,
        batched=True,
        num_proc=num_proc,
        remove_columns=original_columns1,
        load_from_cache_file=False
    )


    ds1.set_format(type="torch")
    return ds1


class DataCollatorWithPadding:

    def paddingtensor(self, intensors, N):
        B, n, S = intensors.shape
        # padding_tensor = torch.zeros(B, N - n, S,dtype=intensors.dtype)
        padding_tensor = torch.zeros(B, N - n, S, dtype=intensors.dtype)
        outtensors = torch.cat((intensors, padding_tensor), dim=1)
        return outtensors

    def paddingtensor2D(self, intensors, N):
        B, n = intensors.shape
        padding_tensor = torch.zeros(B, N - n, dtype=intensors.dtype)
        outtensors = torch.cat((intensors, padding_tensor), dim=1)
        return outtensors

    def __call__(self, features: List[Dict[str, Any]]) -> Dict[str, Any]:
        max_length = max(item['input_ids'].shape[1] for item in features)
        batch_input_ids = torch.cat([self.paddingtensor2D(item['input_ids'], max_length) for item in features])
        batch_attention_mask = torch.cat(
            [self.paddingtensor2D(item['attention_mask'], max_length) for item in features])
        batch_loss_mask = torch.cat(
            [self.paddingtensor2D(item['loss_mask'], max_length) for item in features])

        batch = {
            "input_ids": batch_input_ids,
            "attention_mask": batch_attention_mask,
            "loss_mask": batch_loss_mask,
        }
        return batch


config = EConfig.from_pretrained(train_config["config_path"])

# Pre-compute cache.pt BEFORE model loading to avoid OOM from multiprocessing
# forking after target model is loaded in memory
def _is_valid_cache(cache_path, vocab_size, draft_vocab_size):
    if not os.path.exists(cache_path):
        return False
    try:
        cache = torch.load(cache_path, map_location="cpu")
        t2d = cache.get("t2d")
        d2t = cache.get("d2t")
        if t2d is None or d2t is None:
            return False
        if t2d.numel() != vocab_size or d2t.numel() != draft_vocab_size:
            return False
        selected = int(t2d.sum().item()) if t2d.dtype == torch.bool else int((t2d != 0).sum().item())
        return selected == draft_vocab_size
    except Exception:
        return False


cache_path = "cache.pt"
if not _is_valid_cache(cache_path, config.vocab_size, config.draft_vocab_size):
    if os.path.exists(cache_path):
        print(f"Found incompatible {cache_path}, rebuilding it for vocab={config.vocab_size}, draft_vocab={config.draft_vocab_size}.")
        os.remove(cache_path)
    print("Pre-computing cache.pt (vocabulary statistics)...")
    from cnets_vlm import process_data, merge_dicts
    from collections import Counter
    pre_tokenizer = AutoTokenizer.from_pretrained(args.basepath)
    pre_dataset = load_dataset('json', data_files=args.trainpath)
    pre_dataset = pre_dataset['train']
    pre_columns = pre_dataset.column_names
    
    def pre_process(examples):
        new_examples = {"input_ids": [], "loss_mask": []}
        for i in range(len(examples['id'])):
            messages = [{"role": "system", "content": "You are a helpful, respectful and honest assistant. Always answer as helpfully as possible, while being safe. Your answers should not include any harmful, unethical, racist, sexist, toxic, dangerous, or illegal content. Please ensure that your responses are socially unbiased and positive in nature.\n\nIf a question does not make any sense, or is not factually coherent, explain why instead of answering something not correct. If you don't know the answer to a question, please don't share false information."}]
            convroles = ["user", "assistant"]
            roles = {"human": "user", "gpt": "assistant"}
            source = examples['conversations'][i]
            if not source: continue
            if roles.get(source[0]["from"]) != "user": source = source[1:]
            if not source: continue
            for j, sentence in enumerate(source):
                role = roles.get(sentence["from"], sentence["from"])
                if role != convroles[j % 2]: break
                messages.append({"role": role, "content": sentence["value"]})
            conversation = pre_tokenizer.apply_chat_template(messages, tokenize=False, add_generation_prompt=False)
            if not pre_tokenizer.pad_token_id: pre_tokenizer.pad_token_id = pre_tokenizer.eos_token_id
            input_ids = pre_tokenizer(conversation, return_tensors="pt", add_special_tokens=False).input_ids[0]
            if len(input_ids) > train_config["max_len"]: continue
            loss_mask = torch.ones_like(input_ids)
            sep_assistant = "<|im_start|>assistant\n"
            sep_end = "<|im_end|>"
            loss_mask[:] = 0
            parts = conversation.split(sep_assistant)
            cur_pos = 0
            for pi, part in enumerate(parts):
                if pi == 0:
                    cur_pos += len(pre_tokenizer(part + sep_assistant, add_special_tokens=False).input_ids)
                else:
                    if sep_end in part:
                        response = part.split(sep_end)[0]
                        resp_len = len(pre_tokenizer(response, add_special_tokens=False).input_ids)
                        end_pos = min(cur_pos + resp_len, len(loss_mask))
                        loss_mask[cur_pos:end_pos] = 1
                    cur_pos += len(pre_tokenizer(part + (sep_assistant if pi < len(parts) - 1 else ""), add_special_tokens=False).input_ids)
            new_examples["input_ids"].append(input_ids[None, :])
            new_examples["loss_mask"].append(loss_mask[None, :])
        return new_examples
    
    pre_dataset = pre_dataset.map(pre_process, batched=True, num_proc=8, remove_columns=pre_columns, load_from_cache_file=False)
    chunk_size = len(pre_dataset) // 8 + (len(pre_dataset) % 8 > 0)
    chunks = [pre_dataset[i:i + chunk_size] for i in range(0, len(pre_dataset), chunk_size)]
    import multiprocessing
    with multiprocessing.Pool(8) as pool:
        results = pool.map(process_data, chunks)
    token_dict = merge_dicts(results)
    
    N = config.draft_vocab_size
    total_frequency = sum(token_dict.values())
    top_N = token_dict.most_common(N)
    top_N_frequency_sum = sum(freq for key, freq in top_N)
    print(f"top {N} token frequency ratio: {top_N_frequency_sum / total_frequency:.2%}")
    used_tokens = sorted([key for key, freq in top_N])
    if len(used_tokens) < N:
        used_set = set(used_tokens)
        for token_id in range(config.vocab_size):
            if token_id in used_set:
                continue
            used_tokens.append(token_id)
            if len(used_tokens) == N:
                break
        used_tokens.sort()
    d2t = torch.tensor([used_tokens[i] - i for i in range(len(used_tokens))])
    t2d = torch.tensor([i in used_tokens for i in range(config.vocab_size)])
    torch.save({"d2t": d2t, "t2d": t2d}, cache_path)
    del pre_dataset, pre_tokenizer, chunks, results, token_dict
    print("cache.pt pre-computed successfully!")

tokenizer = AutoTokenizer.from_pretrained(args.basepath)
traindataset = build_dataset_rank(tokenizer, args.trainpath)
testdataset = build_dataset_rank(tokenizer, args.testpath)

# config already created above
model = Model(config, ds_config, train_config, path=args.basepath, load_emb=True, load_head=True)
model.scandata(args.trainpath, args.basepath)



criterion = nn.SmoothL1Loss(reduction="none")

num_epochs = train_config["num_epochs"]

model_engine, optimizer, _, _ = deepspeed.initialize(args=args,
                                                     model=model,
                                                     model_parameters=model.parameters(),
                                                     )

global_rank = deepspeed.comm.get_rank()
rank = deepspeed.comm.get_local_rank()
world_size = deepspeed.comm.get_world_size()
if global_rank == 0:
    print("EAGLE3 training for Qwen2.5-VL (wandb disabled)")

os.makedirs(args.savedir, exist_ok=True)

sampler = DistributedSampler(testdataset, num_replicas=world_size, rank=global_rank, shuffle=False)
test_loader = DataLoader(testdataset, batch_size=train_config["bs"], sampler=sampler, num_workers=4, pin_memory=True,
                         collate_fn=DataCollatorWithPadding())

train_sampler = DistributedSampler(traindataset, num_replicas=world_size, rank=global_rank, shuffle=True)
train_loader = DataLoader(traindataset, batch_size=train_config["bs"], sampler=train_sampler, num_workers=4,
                          pin_memory=True,
                          collate_fn=DataCollatorWithPadding())


def find_max_state_with_file(directory, filename="zero_to_fp32.py"):
    max_a = -1
    for subdir in os.listdir(directory):
        match = re.match(r"state_(\d+)", subdir)
        if match:
            a_value = int(match.group(1))
            subdir_path = os.path.join(directory, subdir)
            file_path = os.path.join(subdir_path, filename)
            if os.path.isdir(subdir_path) and os.path.exists(file_path):
                max_a = max(max_a, a_value)
    if max_a == -1:
        return None, 0
    return f"{directory}/state_{max_a}", max_a + 1


checkpoint_path, start_epoch = find_max_state_with_file(args.savedir)
if checkpoint_path:
    print(f"load from {checkpoint_path}")
    model_engine.load_checkpoint(checkpoint_path)



for epoch in range(start_epoch, num_epochs):
    train_sampler.set_epoch(epoch+1)
    print(f"Now training epoch {epoch}")

    model.train()
    epoch_acces = [[] for _ in range(model.length)]
    epoch_plosses = [[] for _ in range(model.length)]


    for batch_idx, data in enumerate(tqdm(train_loader)):

        model.zero_grad()

        plosses, vlosses, acces = model_engine(input_ids=data["input_ids"].to(rank),
                                               attention_mask=data["attention_mask"].to(rank),
                                               loss_mask=data["loss_mask"],
                                               )

        ploss_weight = [0.8 ** i for i in range(len(plosses))]
        ploss = sum([ploss_weight[i] * plosses[i] for i in range(len(plosses))])
        loss = ploss
        model_engine.backward(loss)


        model_engine.step()

        if global_rank == 0:
            logdict = {"train/lr": optimizer.optimizer.param_groups[0]["lr"]}
            for i in range(len(plosses)):
                logdict[f"train/ploss_{i}"] = plosses[i].item()
            for i in range(len(acces)):
                logdict[f"train/acc_{i}"] = acces[i]
            # Print instead of wandb
            if batch_idx % 100 == 0:
                print(f"Step {batch_idx}: lr={logdict['train/lr']:.2e}, ploss_0={plosses[0].item():.4f}, acc_0={acces[0]:.4f}")
        epoch_acces = [epoch_acces[i] + [acces[i]] for i in range(len(acces))]
        epoch_plosses = [epoch_plosses[i] + [plosses[i].item()] for i in range(len(plosses))]


    for i in range(len(epoch_acces)):
        acc_i = torch.tensor(epoch_acces[i]).cuda().mean()
        deepspeed.comm.all_reduce(acc_i, op=deepspeed.comm.ReduceOp.AVG)
        acc_i = acc_i.item()
        if global_rank == 0:
            print(f"Train Epoch [{epoch + 1}/{num_epochs}], position {i},  Acc: {acc_i:.2f}")

    for i in range(len(epoch_plosses)):
        loss_i = torch.tensor(epoch_plosses[i]).cuda().mean()
        deepspeed.comm.all_reduce(loss_i, op=deepspeed.comm.ReduceOp.AVG)
        loss_i = loss_i.item()
        if global_rank == 0:
            print(f"Train Epoch [{epoch + 1}/{num_epochs}], position {i}, pLoss: {loss_i:.2f}")

    epoch_acces = [[] for _ in range(model.length)]
    epoch_plosses = [[] for _ in range(model.length)]

    for batch_idx, data in enumerate(tqdm(test_loader)):
        with torch.no_grad():
            plosses, vlosses, acces = model_engine(input_ids=data["input_ids"].to(rank),
                                                   attention_mask=data["attention_mask"].to(rank),
                                                   loss_mask=data["loss_mask"],
                                                   )
            epoch_acces = [epoch_acces[i] + [acces[i]] for i in range(len(acces))]
            epoch_plosses = [epoch_plosses[i] + [plosses[i].item()] for i in range(len(plosses))]

    for i in range(len(epoch_acces)):
        acc_i = torch.tensor(epoch_acces[i]).cuda().mean()
        deepspeed.comm.all_reduce(acc_i, op=deepspeed.comm.ReduceOp.AVG)
        acc_i = acc_i.item()
        if global_rank == 0:
            print(f"Test Epoch [{epoch + 1}/{num_epochs}], position {i},  Acc: {acc_i:.2f}")

    for i in range(len(epoch_plosses)):
        loss_i = torch.tensor(epoch_plosses[i]).cuda().mean()
        deepspeed.comm.all_reduce(loss_i, op=deepspeed.comm.ReduceOp.AVG)
        loss_i = loss_i.item()
        if global_rank == 0:
            print(f"Test Epoch [{epoch + 1}/{num_epochs}], position {i}, pLoss: {loss_i:.2f}")
    # clear out the redundance cahce after each step
    torch.cuda.empty_cache()

    model_engine.save_16bit_model(f"{args.savedir}/state_{epoch}", exclude_frozen_parameters=True)
    if epoch % 10 == 0:
        deepspeed.DeepSpeedEngine.save_checkpoint(model_engine, save_dir=f"{args.savedir}/state_{epoch}")
