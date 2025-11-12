import os
import sys
sys.path.insert(0, "TruthfulQA")

import torch
import torch.nn as nn
import torch.nn.functional as F
import llama
from datasets import load_dataset
from tqdm import tqdm
import numpy as np
import llama
import pandas as pd
import warnings
from einops import rearrange
from transformers import AutoTokenizer, AutoModelForCausalLM
from baukit import Trace, TraceDict
import sklearn
from sklearn.metrics import accuracy_score, f1_score, precision_score, recall_score
from sklearn.linear_model import LogisticRegression
import pickle
from functools import partial

# from truthfulqa import utilities, models, metrics
import openai
# from truthfulqa.configs import BEST_COL, ANSWER_COL, INCORRECT_COL

ENGINE_MAP = {
    'llama_7B': 'baffo32/decapoda-research-llama-7B-hf', 
    'alpaca_7B': 'circulus/alpaca-7b', 
    'vicuna_7B': 'AlekseyKorshuk/vicuna-7b', 
    'llama2_chat_7B': 'meta-llama/Llama-2-7b-chat-hf', 
    'llama2_chat_13B': 'meta-llama/Llama-2-13b-chat-hf', 
    'llama2_chat_70B': 'meta-llama/Llama-2-70b-chat-hf', 
}

'''
from truthfulqa.utilities import (
    format_prompt,
    format_prompt_with_answer_strings,
    split_multi_answer,
    format_best,
    find_start,
)
from truthfulqa.presets import preset_map, COMPARE_PRIMER
from truthfulqa.models import find_subsequence, set_columns, MC_calcs
from truthfulqa.evaluate import format_frame, data_to_dict
'''


def load_nq():
    dataset = load_dataset("OamPatel/iti_nq_open_val")["validation"]
    df = pd.DataFrame(columns=["question", "answer", "false_answer"])
    for row in dataset:
        new_row = pd.DataFrame({"question": [row["question"]], "answer": [[_ for _ in row["answer"]]], "false_answer": [row["false_answer"]]})
        df = pd.concat([df, new_row], ignore_index=True)
    return df

def load_triviaqa():
    dataset = load_dataset("OamPatel/iti_trivia_qa_val")["validation"]
    df = pd.DataFrame(columns=["question", "answer", "false_answer"])
    for row in dataset:
        new_row = pd.DataFrame({"question": [row["question"]], "answer": [[_ for _ in row["answer"]['aliases']]], "false_answer": [row["false_answer"]]})
        df = pd.concat([df, new_row], ignore_index=True)
    return df

def format_truthfulqa_DRC(question, choice):
    return f"### Instruction:\n请你对下面的语句作出回复：\n\n### Input:\n{question}\n\n### Response:\n以下是我对该语句的回复：\n{choice}"
   

def format_truthfulqa_Shakespeare(question, choice):
    return f"Please respond to the following statement, and do not output any unnecessary content: \n{question}\nOkay, my answer is as follows:\n{choice}"

def format_truthfulqa_end_q(question, choice, rand_question): 
    # return f"### Instruction:\n请你对下面的语句作出回复：\n\n### Input:\n{question}\n\n### Response:\n以下是我对该语句的回复：\n{choice}\n\n### Instruction:\n请你对下面的语句作出回复：\n\n### Input:\n{rand_question}"
    return f"Please respond to the following statement, and do not output any unnecessary content: \n{question}\nOkay, my answer is as follows:\n{choice}"

def format_with_chat_template(tokenizer, question, choice=None):
    
    messages =  [
        {"role": "user", "content": question+'/no_think'}
    ]
    
    if choice is not None:
        messages.append({"role": "assistant", "content": "<think>\n\n</think>\n\n"+choice})
    
    # 将messages转换为字符串格式
    
    messages_string = tokenizer.apply_chat_template(
        messages,
        add_generation_prompt=False if choice is not None else True,   # 关键：让模型从 assistant 段落开始生成
        tokenize=False
    )
    return messages_string


def tokenized_tqa_gen_end_q(dataset, tokenizer): 

    all_prompts = []
    all_labels = []
    all_categories = []
    for i in range(len(dataset)): 
        question = dataset[i]['question']
        category = dataset[i]['category']
        rand_idx = np.random.randint(len(dataset))
        rand_question = dataset[rand_idx]['question']

        for j in range(len(dataset[i]['correct_answers'])): 
            answer = dataset[i]['correct_answers'][j]
            prompt = format_truthfulqa_end_q(question, answer, rand_question)
            prompt = tokenizer(prompt, return_tensors = 'pt').input_ids
            all_prompts.append(prompt)
            all_labels.append(1)
            all_categories.append(category)
        
        for j in range(len(dataset[i]['incorrect_answers'])):
            answer = dataset[i]['incorrect_answers'][j]
            prompt = format_truthfulqa_end_q(question, answer, rand_question)
            prompt = tokenizer(prompt, return_tensors = 'pt').input_ids
            all_prompts.append(prompt)
            all_labels.append(0)
            all_categories.append(category)
        
    return all_prompts, all_labels, all_categories


def tokenized_tqa_gen_DRC(dataset, tokenizer): 

    all_prompts = []
    all_labels = []
    for i in range(len(dataset)): 
        question = dataset[i]['question']

        for j in range(len(dataset[i]['correct_answers'])): 
            answer = dataset[i]['correct_answers'][j]
            prompt = format_truthfulqa_DRC(question, answer)
            prompt = tokenizer(prompt, return_tensors = 'pt').input_ids
            all_prompts.append(prompt)
            all_labels.append(1)
        
        for j in range(len(dataset[i]['incorrect_answers'])):
            answer = dataset[i]['incorrect_answers'][j]
            prompt = format_truthfulqa_DRC(question, answer)
            prompt = tokenizer(prompt, return_tensors = 'pt').input_ids
            all_prompts.append(prompt)
            all_labels.append(0)
        
    return all_prompts, all_labels

def tokenized_tqa_gen_Shakespeare(dataset, tokenizer): 

    all_prompts = []
    all_labels = []
    for i in range(len(dataset)): 
        question = dataset[i]['question']

        for j in range(len(dataset[i]['correct_answers'])): 
            answer = dataset[i]['correct_answers'][j]
            prompt = format_with_chat_template(tokenizer, question, answer)
            #skip the last <|im_end|>
            prompt = prompt[:-(len('<|im_end|>\n'))]
            prompt = tokenizer(prompt, return_tensors = 'pt').input_ids
            all_prompts.append(prompt)
            all_labels.append(1)
        
        for j in range(len(dataset[i]['incorrect_answers'])):
            answer = dataset[i]['incorrect_answers'][j]
            prompt = format_with_chat_template(tokenizer, question, answer)
            prompt = prompt[:-(len('<|im_end|>\n'))]
            prompt = tokenizer(prompt, return_tensors = 'pt').input_ids
            all_prompts.append(prompt)
            all_labels.append(0)
        
    return all_prompts, all_labels

def get_llama_activations_bau(model, prompt, device): 

    HEADS = [f"model.layers.{i}.self_attn.head_out" for i in range(model.config.num_hidden_layers)]
    MLPS = [f"model.layers.{i}.mlp" for i in range(model.config.num_hidden_layers)]

    with torch.no_grad():
        prompt = prompt.to(device)
        with TraceDict(model, HEADS+MLPS) as ret:
            output = model(prompt, output_hidden_states = True)
        hidden_states = output.hidden_states
        hidden_states = torch.stack(hidden_states, dim = 0).squeeze()
        hidden_states = hidden_states.detach().cpu().numpy()
        head_wise_hidden_states = [ret[head].output.squeeze().detach().cpu() for head in HEADS]
        head_wise_hidden_states = torch.stack(head_wise_hidden_states, dim = 0).squeeze().numpy()
        mlp_wise_hidden_states = [ret[mlp].output.squeeze().detach().cpu() for mlp in MLPS]
        mlp_wise_hidden_states = torch.stack(mlp_wise_hidden_states, dim = 0).squeeze().numpy()

    return hidden_states, head_wise_hidden_states, mlp_wise_hidden_states


def get_llama_logits(model, prompt, device): 

    model.eval()
    with torch.no_grad(): 
        prompt = prompt.to(device)
        logits = model(prompt).logits
        logits = logits.detach().cpu()
        return logits

def save_probes(probes, path): 
    """takes in a list of sklearn lr probes and saves them to path"""
    with open(path, 'wb') as f: 
        pickle.dump(probes, f)

def load_probes(path): 
    """loads a list of sklearn lr probes from path"""
    with open(path, 'rb') as f: 
        probes = pickle.load(f)
    return probes



def run_ce_loss(model_key, model=None, tokenizer=None, device='cuda', interventions={}, intervention_fn=None, num_samples=100): 

    # load owt text
    # note this is tokenized with llama tokenizer
    dataset = load_dataset("stas/openwebtext-10k")['train']
    dataset = dataset.shuffle()
    dataset = dataset.select(range(num_samples))

    # tokenize
    owt = dataset.map(lambda x: {'input_ids': torch.tensor(tokenizer(x['text'], return_tensors='pt')['input_ids'][:,:128])})
    owt.set_format(type='torch', columns=['input_ids'])
    
    # define intervention
    def id(head_output, layer_name):
        return head_output
    
    if interventions == {}:
        layers_to_intervene = []
        intervention_fn = id
    else: 
        layers_to_intervene = list(interventions.keys())
        intervention_fn = partial(intervention_fn, start_edit_location=0)

    losses = []
    rand_idxs = np.random.choice(len(owt), num_samples, replace=False).tolist()
    with torch.no_grad(): 
        for i in tqdm(rand_idxs):

            input_ids = owt[i]['input_ids'][:, :128].to(device)
            
            with TraceDict(model, layers_to_intervene, edit_output=intervention_fn) as ret:
                loss = model(input_ids, labels=input_ids).loss
            
            losses.append(loss.item())
    
    return np.mean(losses)

def run_kl_wrt_orig(model_key, model=None, tokenizer=None, device='cuda', interventions={}, intervention_fn=None, num_samples=100, separate_kl_device=None): 

    assert 'llama' in model_key or 'alpaca' in model_key or 'vicuna' in model_key, 'model must be llama model'

    # load owt text
    # note this is tokenized with llama tokenizer
    dataset = load_dataset("stas/openwebtext-10k")['train']
    dataset = dataset.shuffle()
    dataset = dataset.select(range(num_samples))

    # tokenize
    owt = dataset.map(lambda x: {'input_ids': torch.tensor(tokenizer(x['text'], return_tensors='pt')['input_ids'][:,:128])})
    owt.set_format(type='torch', columns=['input_ids'])
    
    # define intervention
    def id(head_output, layer_name):
        return head_output
    
    if interventions == {}:
        layers_to_intervene = []
        intervention_fn = id
    else: 
        layers_to_intervene = list(interventions.keys())
        intervention_fn = partial(intervention_fn, start_edit_location=0)

    kl_divs = []
    rand_idxs = np.random.choice(len(owt), num_samples, replace=False).tolist()

    if separate_kl_device is not None: 
        orig_model = llama.LLaMAForCausalLM.from_pretrained(ENGINE_MAP[model_key], torch_dtype=torch.float16, low_cpu_mem_usage=True)
        orig_model.to('cuda')

    with torch.no_grad(): 
        for i in tqdm(rand_idxs):
            input_ids = owt[i]['input_ids'][:, :128].to(device)

            if separate_kl_device is not None: 
                orig_logits = orig_model(input_ids.to('cuda')).logits.cpu().type(torch.float32)
            else: 
                orig_logits = model(input_ids).logits.cpu().type(torch.float32)
                
            orig_probs = F.softmax(orig_logits, dim=-1)

            with TraceDict(model, layers_to_intervene, edit_output=intervention_fn) as ret:
                logits = model(input_ids).logits.cpu().type(torch.float32)
                probs  = F.softmax(logits, dim=-1)
            
            kl_div = (orig_probs * (orig_probs / probs).log()).sum() / (input_ids.shape[-1] * input_ids.shape[-2])
            kl_divs.append(kl_div.item())

    return np.mean(kl_divs)


def flattened_idx_to_layer_head(flattened_idx, num_heads):
    return flattened_idx // num_heads, flattened_idx % num_heads

def layer_head_to_flattened_idx(layer, head, num_heads):
    return layer * num_heads + head

def train_probes(seed, train_set_idxs, val_set_idxs, separated_head_wise_activations, separated_labels, num_layers, num_heads):
    
    all_head_accs = []
    probes = []

    all_X_train = np.concatenate([separated_head_wise_activations[i] for i in train_set_idxs], axis = 0)
    all_X_val = np.concatenate([separated_head_wise_activations[i] for i in val_set_idxs], axis = 0)
    y_train = np.concatenate([separated_labels[i] for i in train_set_idxs], axis = 0)
    y_val = np.concatenate([separated_labels[i] for i in val_set_idxs], axis = 0)

    for layer in tqdm(range(num_layers)): 
        for head in range(num_heads): 
            X_train = all_X_train[:,layer,head,:]
            X_val = all_X_val[:,layer,head,:]
    
            clf = LogisticRegression(random_state=seed, max_iter=1000).fit(X_train, y_train)
            y_pred = clf.predict(X_train)
            y_val_pred = clf.predict(X_val)
            all_head_accs.append(accuracy_score(y_val, y_val_pred))
            probes.append(clf)

    all_head_accs_np = np.array(all_head_accs)

    return probes, all_head_accs_np

def get_top_heads(train_idxs, val_idxs, separated_activations, separated_labels, num_layers, num_heads, seed, num_to_intervene, use_random_dir=False):

    probes, all_head_accs_np = train_probes(seed, train_idxs, val_idxs, separated_activations, separated_labels, num_layers=num_layers, num_heads=num_heads)
    all_head_accs_np = all_head_accs_np.reshape(num_layers, num_heads)

    top_heads = []

    top_accs = np.argsort(all_head_accs_np.reshape(num_heads*num_layers))[::-1][:num_to_intervene]
    # print(all_head_accs_np)
    # print(top_accs)
    
    top_heads = [flattened_idx_to_layer_head(idx, num_heads) for idx in top_accs]
    if use_random_dir: 
        # overwrite top heads with random heads, no replacement
        random_idxs = np.random.choice(num_heads*num_layers, num_heads*num_layers, replace=False)
        top_heads = [flattened_idx_to_layer_head(idx, num_heads) for idx in random_idxs[:num_to_intervene]]

    return top_heads, probes

def get_interventions_dict(top_heads, probes, tuning_activations, num_heads, use_center_of_mass, use_random_dir, com_directions): 

    interventions = {}
    for layer, head in top_heads: 
        interventions[f"model.layers.{layer}.self_attn.head_out"] = []
    for layer, head in top_heads:
        if use_center_of_mass: 
            direction = com_directions[layer_head_to_flattened_idx(layer, head, num_heads)]
        elif use_random_dir: 
            direction = np.random.normal(size=(128,))
        else: 
            direction = probes[layer_head_to_flattened_idx(layer, head, num_heads)].coef_
        direction = direction / np.linalg.norm(direction)
        activations = tuning_activations[:,layer,head,:] # batch x 128
        proj_vals = activations @ direction.T
        proj_val_std = np.std(proj_vals)
        interventions[f"model.layers.{layer}.self_attn.head_out"].append((head, direction.squeeze(), proj_val_std))
    for layer, head in top_heads: 
        interventions[f"model.layers.{layer}.self_attn.head_out"] = sorted(interventions[f"model.layers.{layer}.self_attn.head_out"], key = lambda x: x[0])

    return interventions

def get_separated_activations(labels, head_wise_activations): 

    # separate activations by question
    # dataset=load_dataset('truthful_qa', 'multiple_choice')['validation']
    # actual_labels = []
    # for i in range(len(dataset)):
    #    actual_labels.append(dataset[i]['mc2_targets']['labels'])

    # idxs_to_split_at = np.cumsum([len(x) for x in actual_labels])     
    idxs_to_split_at = np.cumsum([2 for _ in range(len(labels) // 2)])     

    labels = list(labels)
    separated_labels = []
    for i in range(len(idxs_to_split_at)):
        if i == 0:
            separated_labels.append(labels[:idxs_to_split_at[i]])
        else:
            separated_labels.append(labels[idxs_to_split_at[i-1]:idxs_to_split_at[i]])
    # assert separated_labels == actual_labels
    # print(separated_labels)

    separated_head_wise_activations = np.split(head_wise_activations, idxs_to_split_at)

    return separated_head_wise_activations, separated_labels, idxs_to_split_at

def get_com_directions(num_layers, num_heads, train_set_idxs, val_set_idxs, separated_head_wise_activations, separated_labels): 

    com_directions = []

    for layer in range(num_layers): 
        for head in range(num_heads): 
            usable_idxs = np.concatenate([train_set_idxs, val_set_idxs], axis=0)
            usable_head_wise_activations = np.concatenate([separated_head_wise_activations[i][:,layer,head,:] for i in usable_idxs], axis=0)
            usable_labels = np.concatenate([separated_labels[i] for i in usable_idxs], axis=0)
            true_mass_mean = np.mean(usable_head_wise_activations[usable_labels == 1], axis=0)
            false_mass_mean = np.mean(usable_head_wise_activations[usable_labels == 0], axis=0)
            com_directions.append(true_mass_mean - false_mass_mean)
    com_directions = np.array(com_directions)

    return com_directions

def zero_qwen3_attention_biases(model):
    """
    Zero-initialize bias terms for q_proj, k_proj, v_proj, and o_proj across all
    self-attention layers in a Qwen3-like model. Layers without bias are skipped.
    
    Returns:
        int: Number of Linear modules whose bias was zeroed.
    """
    num_zeroed = 0
    # Expecting a structure like model.model.layers[i].self_attn.{q_proj,k_proj,v_proj,o_proj}
    base = getattr(model, "model", None)
    layers = getattr(base, "layers", None) if base is not None else None
    if layers is None:
        return num_zeroed
    for layer in layers:
        attn = getattr(layer, "self_attn", None)
        if attn is None:
            continue
        for proj_name in ("q_proj", "k_proj", "v_proj", "o_proj"):
            proj = getattr(attn, proj_name, None)
            if proj is not None and getattr(proj, "bias", None) is not None:
                nn.init.zeros_(proj.bias)
                num_zeroed += 1
    return num_zeroed
