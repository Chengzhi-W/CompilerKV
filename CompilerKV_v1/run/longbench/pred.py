import os
import json
import random
import argparse
from pathlib import Path

import numpy as np
from tqdm import tqdm

import torch
from transformers import AutoModelForCausalLM, AutoTokenizer
import sys
PROJECT_ROOT = Path(__file__).resolve().parents[2]
sys.path.insert(0, str(PROJECT_ROOT))
from kv_compression.token_drop.monkeypatch import replace_attention
datasets = ["narrativeqa", "qasper", "multifieldqa_en", "hotpotqa", "2wikimqa", "musique", \
            "gov_report", "qmsum", "multi_news", "trec", "triviaqa", "samsum", \
            "passage_count", "passage_retrieval_en", "lcc", "repobench-p"]

dataset2maxlen = {
    "narrativeqa": 128,
    "qasper": 128,
    "multifieldqa_en": 64,
    "multifieldqa_zh": 64,
    "hotpotqa": 32,
    "2wikimqa": 32,
    "musique": 32,
    "dureader": 128,
    "gov_report": 512,
    "qmsum": 512,
    "multi_news": 512,
    "vcsum": 512,
    "trec": 64,
    "triviaqa": 32,
    "samsum": 128,
    "lsht": 64,
    "passage_count": 32,
    "passage_retrieval_en": 32,
    "passage_retrieval_zh": 32,
    "lcc": 64,
    "repobench-p": 64
}

model2prompt = {
    "narrativeqa": "You are given a story, which can be either a novel or a movie script, and a question. Answer the question asconcisely as you can, using a single phrase if possible. Do not provide any explanation.\n\nStory: {context}\n\nNow, answer the question based on the story asconcisely as you can, using a single phrase if possible. Do not provide any explanation.\n\nQuestion: {input}\n\nAnswer:",
    "qasper": "You are given a scientific article and a question. Answer the question as concisely as you can, using a single phrase or sentence if possible. If the question cannot be answered based on the information in the article, write \"unanswerable\". If the question is a yes/no question, answer \"yes\", \"no\", or \"unanswerable\". Do not provide any explanation.\n\nArticle: {context}\n\n Answer the question based on the above article as concisely as you can, using a single phrase or sentence if possible. If the question cannot be answered based on the information in the article, write \"unanswerable\". If the question is a yes/no question, answer \"yes\", \"no\", or \"unanswerable\". Do not provide any explanation.\n\nQuestion: {input}\n\nAnswer:",
    "multifieldqa_en": "Read the following text and answer briefly.\n\n{context}\n\nNow, answer the following question based on the above text, only give me the answer and do not output any other words.\n\nQuestion: {input}\nAnswer:",
    "multifieldqa_zh": "阅读以下文字并用中文简短回答：\n\n{context}\n\n现在请基于上面的文章回答下面的问题，只告诉我答案，不要输出任何其他字词。\n\n问题：{input}\n回答：",
    "hotpotqa": "Answer the question based on the given passages. Only give me the answer and do not output any other words.\n\nThe following are given passages.\n{context}\n\nAnswer the question based on the given passages. Only give me the answer and do not output any other words.\n\nQuestion: {input}\nAnswer:",
    "2wikimqa": "Answer the question based on the given passages. Only give me the answer and do not output any other words.\n\nThe following are given passages.\n{context}\n\nAnswer the question based on the given passages. Only give me the answer and do not output any other words.\n\nQuestion: {input}\nAnswer:",
    "musique": "Answer the question based on the given passages. Only give me the answer and do not output any other words.\n\nThe following are given passages.\n{context}\n\nAnswer the question based on the given passages. Only give me the answer and do not output any other words.\n\nQuestion: {input}\nAnswer:",
    "dureader": "请基于给定的文章回答下述问题。\n\n文章：{context}\n\n请基于上述文章回答下面的问题。\n\n问题：{input}\n回答：",
    "gov_report": "You are given a report by a government agency. Write a one-page summary of the report.\n\nReport:\n{context}\n\nNow, write a one-page summary of the report.\n\nSummary:",
    "qmsum": "You are given a meeting transcript and a query containing a question or instruction. Answer the query in one or more sentences.\n\nTranscript:\n{context}\n\nNow, answer the query based on the above meeting transcript in one or more sentences.\n\nQuery: {input}\nAnswer:",
    "multi_news": "You are given several news passages. Write a one-page summary of all news. \n\nNews:\n{context}\n\nNow, write a one-page summary of all the news.\n\nSummary:",
    "vcsum": "下面有一段会议记录，请你阅读后，写一段总结，总结会议的内容。\n会议记录：\n{context}\n\n会议总结：",
    "trec": "Please determine the type of the question below. Here are some examples of questions.\n\n{context}\n{input}",
    "triviaqa": "Answer the question based on the given passage. Only give me the answer and do not output any other words. The following are some examples.\n\n{context}\n\n{input}",
    "samsum": "Summarize the dialogue into a few short sentences. The following are some examples.\n\n{context}\n\n{input}",
    "lsht": "请判断给定新闻的类别，下面是一些例子。\n\n{context}\n{input}",
    "passage_count": "There are some paragraphs below sourced from Wikipedia. Some of them may be duplicates. Please carefully read these paragraphs and determine how many unique paragraphs there are after removing duplicates. In other words, how many non-repeating paragraphs are there in total?\n\n{context}\n\nPlease enter the final count of unique paragraphs after removing duplicates. The output format should only contain the number, such as 1, 2, 3, and so on.\n\nThe final answer is: ",
    "passage_retrieval_en": "Here are 30 paragraphs from Wikipedia, along with an abstract. Please determine which paragraph the abstract is from.\n\n{context}\n\nThe following is an abstract.\n\n{input}\n\nPlease enter the number of the paragraph that the abstract is from. The answer format must be like \"Paragraph 1\", \"Paragraph 2\", etc.\n\nThe answer is: ",
    "passage_retrieval_zh": "以下是若干段落文字，以及其中一个段落的摘要。请确定给定的摘要出自哪一段。\n\n{context}\n\n下面是一个摘要\n\n{input}\n\n请输入摘要所属段落的编号。答案格式必须是\"段落1\"，\"段落2\"等格式\n\n答案是：",
    "lcc": "Please complete the code given below. \n{context}Next line of code:\n",
    "repobench-p": "Please complete the code given below. \n{context}{input}Next line of code:\n"
}


model2maxlen = {
    "llama2": 3950,
    "llama-2": 3950,
    "llama3": 7950,
    "llama-3": 7950,
    "mistral": 31500,
    "qwen2": 31500,
    "lwm": 1048576,
    "internlm": 1048576
}



def set_seed(seed):
    torch.manual_seed(seed)
    torch.cuda.manual_seed(seed)
    np.random.seed(seed)
    random.seed(seed)
    torch.backends.cudnn.benchmark = False
    torch.backends.cudnn.deterministic = True
    torch.cuda.manual_seed_all(seed)

def build_chat(prompt):
        prompt = f"[INST] {prompt} [/INST]"
        return prompt

def inference_preds(args):
    if args.method.lower() == "compilerkv" and args.eval_batch_size != 1:
        raise ValueError("CompilerKV's elastic cache requires --eval_batch_size 1 in the legacy runner")
    if args.method.lower() == "compilerkv" and not args.tables_dir:
        raise ValueError("--tables_dir must point to artifacts produced by compilerkv-compile")
    prompt_ppl = {}
    if args.prompt_ppl_file:
        with open(args.prompt_ppl_file, encoding="utf-8") as stream:
            prompt_ppl = json.load(stream)
    print("Loading data...")  
    test_data = []  
    prompts = []
    inputs = []
    contexts = []
    answerss = []
    lengths = []
    datasets = []
    languages = []
    all_classess = []
    _ids = []
    input_max_len = 0
    
    model_max_len = int(min(getattr(tokenizer, "model_max_length", 32768), 1_048_576))
    for key in model2maxlen:
        if key in args.model_path:
            model_max_len = model2maxlen[key]
    print(f"Current model {args.model_name}\tmax len {model_max_len}")
    output_max_len = dataset2maxlen[args.dataset]
    
    with open(args.data_file) as fp:
        for line in fp:
            example = json.loads(line)
            length = example["length"]
            if length > input_max_len: input_max_len = length
            
            prompt = model2prompt[args.dataset].format(**example)

            example["prompt"] = prompt
                
            test_data.append(example)
        
    print(f"Max Length is {input_max_len}")
        
    if args.max_num_examples and len(test_data) > args.max_num_examples:
        if args.sample_method == "random":
            test_data = random.sample(test_data, args.max_num_examples)
        elif args.sample_method == "topk":
            test_data = test_data[:args.max_num_examples]
    
    
    for example in test_data:
        
        prompts.append(example["prompt"])
        inputs.append(example["input"])
        contexts.append(example["context"])
        answerss.append(example["answers"])
        lengths.append(example["length"])
        datasets.append(example["dataset"])
        languages.append(example["language"])
        all_classess.append(example["all_classes"])
        _ids.append(example["_id"])

    print("Finish loading model and tokenizer")
    args.method = args.method.lower()
    prefix_name = f"{args.model_name}_{args.method}_{args._raw_cap}_{args.window_size}_{args.kernel_sizes}_{args.pooling}"
    os.makedirs(os.path.join(args.save_dir, prefix_name, args.dataset), exist_ok=True)
    fout = open(os.path.join(args.save_dir, prefix_name, args.dataset, f"{args.method}.json"), "w")
     
    for i in tqdm(range(0, len(prompts), args.eval_batch_size)):
        
        batch_prompts = prompts[i:i+args.eval_batch_size]
        batch_inputs = inputs[i:i+args.eval_batch_size]
        batch_contexts = contexts[i:i+args.eval_batch_size]
        batch_answerss = answerss[i:i+args.eval_batch_size]
        batch_lengths = lengths[i:i+args.eval_batch_size]
        
        batch_datasets = datasets[i:i+args.eval_batch_size]
        batch_languages = languages[i:i+args.eval_batch_size]
        batch_all_classess = all_classess[i:i+args.eval_batch_size]
        batch__ids = _ids[i:i+args.eval_batch_size]
        
        tokenized_prompts = tokenizer(batch_prompts, padding="longest", return_tensors="pt", add_special_tokens=True).to('cuda')
        batch_input_ids = tokenized_prompts.input_ids

        if len(batch_input_ids[0]) > model_max_len:
            half = int(model_max_len/2)
            prompt = tokenizer.decode(batch_input_ids[0][:half], skip_special_tokens=True)+tokenizer.decode(batch_input_ids[0][-half:], skip_special_tokens=True)
            tokenized_prompts = tokenizer(prompt, padding="longest", return_tensors="pt", add_special_tokens=True).to('cuda')
            batch_input_ids = tokenized_prompts.input_ids
        
        if args.max_capacity_prompts != -1:
            max_capacity_prompts = args.max_capacity_prompts
        elif args.max_capacity_prompts_ratio != -1:
            max_capacity_prompts = round(batch_input_ids.shape[1] * args.max_capacity_prompts_ratio)
        
        if args.method != "fullkv":
            if args.method == "pyramidkv":
                window_sizes = 8
            elif args.method in ["snapkv", "streamingllm", "h2o"]:
                window_sizes = 32
            else:
                window_sizes = args.window_size
    
            kernel_sizes = args.kernel_sizes
            pooling = args.pooling
            
            layers = len(model.model.layers)
            current_ppl = args.prompt_ppl
            if prompt_ppl:
                current_ppl = prompt_ppl.get(str(batch__ids[0]))
            # check if window_sizes is a list
            if "internlm" in args.model_name:
                for i in range(layers):
                    attention = model.model.layers[i].attention
                    attention.config.window_size = window_sizes
                    attention.config.max_capacity_prompt = max_capacity_prompts
                    attention.config.kernel_size = kernel_sizes
                    attention.config.pooling = pooling
                    attention.config.tables_dir = args.tables_dir
                    attention.config.prompt_ppl = current_ppl
                    attention.config.missing_ppl = args.missing_ppl
                    if hasattr(attention, "kv_cluster"):
                        attention.kv_cluster.prompt_ppl = current_ppl
                    if "dynamic" in args.method :
                        attention.config.radio_max = args.radio_max
            else:
                for i in range(layers):
                    attention = model.model.layers[i].self_attn
                    attention.config.window_size = window_sizes
                    attention.config.max_capacity_prompt = max_capacity_prompts
                    attention.config.kernel_size = kernel_sizes
                    attention.config.pooling = pooling
                    attention.config.tables_dir = args.tables_dir
                    attention.config.prompt_ppl = current_ppl
                    attention.config.missing_ppl = args.missing_ppl
                    if hasattr(attention, "kv_cluster"):
                        attention.kv_cluster.prompt_ppl = current_ppl
                    if "dynamic" in args.method :
                        attention.config.radio_max = args.radio_max
                    

        context_length = batch_input_ids.shape[-1]
        if args.dataset == "samsum":
            output = model.generate(
                **tokenized_prompts,
                max_new_tokens=output_max_len,
                num_beams=1,
                do_sample=False,
                temperature=1.0,
                min_length=context_length+1,
                eos_token_id=[tokenizer.eos_token_id, tokenizer.encode("\n", add_special_tokens=False)[-1]]
            )
        else:
            output = model.generate(
                **tokenized_prompts,
                max_new_tokens=output_max_len,
                num_beams=1,
                do_sample=False,
                temperature=1.0,
            )


        batch_outputs = tokenizer.batch_decode(
            output[:, context_length:], skip_special_tokens=True
        )
        
        
        batch_generations = batch_outputs

        torch.cuda.empty_cache()

        for j in range(len(batch_outputs)):
            
            example = {}
            
            example["prompt"] = batch_prompts[j]
            example["input"] = batch_inputs[j]
            example["context"] = batch_contexts[j]
            example["answers"] = batch_answerss[j]
            example["pred"] = batch_generations[j]
            example["length"] = batch_lengths[j]
            
            example["dataset"] = batch_datasets[j]
            example["language"] = batch_languages[j]
            example["all_classes"] = batch_all_classess[j]
            example["_id"] = batch__ids[j]


            fout.write(json.dumps(example) + "\n")
    
    


def _args(parser):
    parser.add_argument("--seed", type=int, default=42, help="")
    parser.add_argument("--dataset_file", type=str, default=str(PROJECT_ROOT / "data" / "LongBench"))
    parser.add_argument("--data_file", type=str, default="")
    parser.add_argument("--save_dir", type=str, default=str(PROJECT_ROOT / "results"))
    parser.add_argument("--model_name", type=str, default=None, help="if specified, we will load the model to generate the predictions.")
    parser.add_argument("--model_path", type=str, default="meta-llama/Meta-Llama-3-8B-Instruct", help="local checkpoint or Hugging Face model id")
    parser.add_argument(
        "--use_fast_tokenizer",
        action=argparse.BooleanOptionalAction,
        default=True,
    )
    parser.add_argument("--max_num_examples", type=int, default=None, help="maximum number of examples to evaluate per task.")
    parser.add_argument("--sample_method", type=str, default="topk", choices=["random", "topk"], help="how to sample the examples.")
    parser.add_argument("--max_new_tokens", type=int, default=None, help="")
    parser.add_argument("--eval_batch_size", type=int, default=1, help="batch size for evaluation.")
    parser.add_argument("--use_cache", action=argparse.BooleanOptionalAction, default=True)
    parser.add_argument("--attn_implementation", type=str,  default="flash_attention_2", choices=["flash_attention_2", "sdpa", "eager"])
    parser.add_argument("--method", type=str, default="compilerkv")
    parser.add_argument("--max_capacity_prompts", type=int, default=512, help="per-layer total KV budget")
    parser.add_argument("--window_size", type=int, default=64, help="observation window")
    parser.add_argument("--max_capacity_prompts_ratio", type=float, default=-1, help="")
    parser.add_argument("--use_chat_format", action="store_true", help="If given, we will use the chat format for the prompts.")
    parser.add_argument("--kernel_sizes", type=int, default=7, help="")
    parser.add_argument("--pooling", type=str, default="avgpool", help="")
    parser.add_argument("--radio_max", type=float, default=5.0, help="")
    parser.add_argument("--tables_dir", type=str, default=None)
    parser.add_argument("--prompt_ppl", type=float, default=None)
    parser.add_argument("--prompt_ppl_file", type=str, default=None, help="JSON map from LongBench _id to local PPL")
    parser.add_argument("--missing_ppl", choices=["error", "median"], default="error")
    args = parser.parse_args()
    args._raw_cap = args.max_capacity_prompts
 
    return args

if __name__ == "__main__":

    parser = argparse.ArgumentParser()
    
    args = _args(parser)
    
    print("--"*10)
    print(args)
    print("--"*10)
    
    set_seed(args.seed)
    
    tokenizer = AutoTokenizer.from_pretrained(
        args.model_path,
        use_fast=args.use_fast_tokenizer,
        padding_side="left",
        trust_remote_code=True
    )
    model = AutoModelForCausalLM.from_pretrained(
        args.model_path,
        torch_dtype="auto",
        low_cpu_mem_usage=True,
        device_map="auto",
        use_cache=args.use_cache,
        attn_implementation=args.attn_implementation,
        trust_remote_code=True ## internlm 09.02 zxb
    )
    if args.model_name is None:
        args.model_name = args.model_path.split("/")[-1].lower()
    args.model_name = args.model_name.lower()
    args.model_path = args.model_path.lower()
    
    if "llama" in args.model_name:
        replace_attention(model_type="llama", method=args.method.lower())
    elif "mistral" in args.model_name:
        replace_attention(model_type="mistral", method=args.method.lower())
    elif "qwen2" in args.model_name:
        replace_attention(model_type="qwen2", method=args.method.lower())
    elif "internlm" in args.model_name:
        replace_attention(model_type="internlm", method=args.method.lower())
        
        
    tokenizer.padding_side = "left"
    if tokenizer.pad_token is None:
        tokenizer.pad_token = tokenizer.eos_token
        tokenizer.pad_token_id = tokenizer.eos_token_id
        
    model.eval()

    for idx, dataset in enumerate(datasets):
        
        print(f"Working on max_capacity_prompts {args.max_capacity_prompts} dataset {dataset} - {idx}/{len(datasets)}")
        
        args.dataset = dataset
        
        args.data_file = f"{args.dataset_file}/{args.dataset}.jsonl"
        
        inference_preds(args)
