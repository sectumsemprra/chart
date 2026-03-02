import os
import tqdm
import re
import time
import pickle
import random
import argparse
import json
import io
os.environ["FLASH_ATTENTION_2_ENABLED"] = "1"

import torch
import numpy as np
from transformers import BitsAndBytesConfig
from transformers import AutoModel, AutoProcessor, AutoTokenizer
from peft import LoraConfig, get_peft_model, PeftModel
from trl import SFTConfig, SFTTrainer, DPOConfig, DPOTrainer
import wandb
import sacrebleu

from qwen_vl_utils import process_vision_info



from models import load_vlm_model
from dataset_process import ChartDataset, PlotQADataset, ChartToTextDataset


from metrics import exact_match, relaxed_accuracy
from utils import get_vlm_output, clear_memory, format_data, select_icl_samples

import logging, os


seed = 2026


logging.basicConfig(
    level=logging.INFO,
    format="%(asctime)s | %(levelname)s | %(name)s | %(message)s"
)

cache_dir = '/content/hf_cache'
os.environ['HF_HUB_CACHE'] = '/content/hf_cache'
os.environ['TRANSFORMERS_CACHE']= '/content/hf_cache'
os.environ['HF_HOME'] = '/content/hf_cache'

def parse_args():
    parser = argparse.ArgumentParser(description="Argument parser for VLM evaluation pipeline")

    parser.add_argument('--mode', type=str, choices=["eval", "sft", "dpo", "ppo", "grpo", "psr", "nsr", "w-reinforce"], required=True, help='Run mode: eval, sft, dpo, ppo, grpo, psr (Positive Sample Reinforcement), nsr (Negative Sample Reinforcement), w-reinforce (Weighted-REINFORCE)')
    parser.add_argument('--vlm-name', type=str, required=True, help='Name of the vision-language model')
    parser.add_argument('--sft-lora', type=bool, required=False, default=False, help='Use LORA adapters for SFT and location')
    parser.add_argument('--dpo-lora', type=bool, required=False, default=False, help='Use LORA adapters for DPO and location')
    parser.add_argument('--grpo-lora', type=bool, required=False, default=False, help='Use LORA adapters for GRPO and location')
    parser.add_argument('--dataset-name', type=str, required=True, help='Name of the dataset to use')
    parser.add_argument('--dataset-split', type=str, required=False, default = "test", help='Dataset split')
    parser.add_argument('--seed', type=int, default=2025, help='Random seed')
    parser.add_argument('--cot', type=bool, default=False, help='To use CoT or not')
    parser.add_argument('--icl', type=bool, default=False, help='To use ICL examples for inference or not')
    parser.add_argument('--hard', type=bool, default=False, help='To use hard example trained models for inference')

    # GRPO Training Speed Optimization Arguments
    parser.add_argument('--subset-size', type=int, default=None, help='Use subset of training data for faster training (e.g., 10000). None = full dataset')
    parser.add_argument('--num-epochs', type=int, default=4, help='Number of training epochs (default: 4, reduce to 1-2 for faster training)')
    parser.add_argument('--num-generations', type=int, default=4, help='Number of generations per sample for GRPO (default: 4, reduce to 2 for 50%% speedup)')
    parser.add_argument('--batch-size', type=int, default=2, help='Per-device training batch size (default: 2, increase to 4 for fewer steps)')
    parser.add_argument('--disable-gradient-checkpointing', action='store_true', help='Disable gradient checkpointing for 20-30%% speedup (uses more memory)')

    # NSR Training Mode Arguments (PSR, NSR, W-REINFORCE)
    parser.add_argument('--lambda-psr', type=float, default=0.1, help='Weight for PSR in W-REINFORCE mode (default: 0.1, paper recommendation)')
    parser.add_argument('--reward-threshold', type=float, default=0.5, help='Threshold to separate positive/negative samples (default: 0.5)')

    return parser.parse_args()

def set_all_seeds(seed: int = 2025) -> None:
    """Sets the random seed for PyTorch, NumPy, and Python's random module."""
    np.random.seed(seed)
    random.seed(seed)
    torch.manual_seed(seed)
    if torch.cuda.is_available():
        torch.cuda.manual_seed(seed) # For current GPU
        torch.cuda.manual_seed_all(seed) # For all GPUs
    
    # When running on the CuDNN backend, two further options must be set for full determinism.
    torch.backends.cudnn.deterministic = True
    torch.backends.cudnn.benchmark = False
    
    # Set a fixed value for the hash seed to ensure consistent hashing behavior
    os.environ["PYTHONHASHSEED"] = str(seed)
    print(f"Random seed set as {seed}")


set_all_seeds(seed)


if __name__ == "__main__":
    # Parse command line arguments
    args = parse_args()

    # TODO: Load the model and processor for chart specific models (they dont work with batched inputs)
    model, processor = load_vlm_model(args.vlm_name, args.mode)
    logging.info("Loaded model and processor")

    if args.mode == "sft" or args.mode == "dpo" or args.mode == "grpo":
        # Set the PEFT 
        if "qwen" in args.vlm_name:
            # target_modules=["q_proj", "k_proj", "v_proj", "o_proj", "gate_proj", "up_proj", "down_proj"]
            target_modules=["q_proj", "v_proj"]
        elif "intern" in args.vlm_name:
            target_modules=["wqkv", "wo", "w1", "w2", "w3"]
        else:
            target_modules = None # This targets all possible layers/modules (llava type models, maybe pali #TODO check)

    if args.dataset_name == "chartqa":
        dataset = ChartDataset("chartqa", processor=processor)
        test_dataset = dataset.load_chart_dataset(split = "test")
        if args.mode == "sft" or args.icl:
            train_dataset = dataset.load_chart_dataset(split = "train")
        if args.mode == "sft":
            eval_dataset = dataset.load_chart_dataset(split = "val") 

    if args.dataset_name == "chartqa-src":
        dataset = ChartDataset("chartqa-src", processor=processor)
        test_dataset = dataset.load_chart_dataset(split = "test")
        if args.mode in ["sft", "dpo", "grpo"] or args.icl:
            train_dataset = dataset.load_chart_dataset(split = "train")
        if args.mode in ["sft", "dpo", "grpo"]:
            eval_dataset = dataset.load_chart_dataset(split = "val") 

    if args.dataset_name == "chartfc":
        dataset = ChartDataset("chartfc", processor=processor)
        test_dataset = dataset.load_chart_dataset(split = "test")

    elif args.dataset_name == "chartqapro":
        dataset = ChartDataset("chartqapro", processor=processor)
        test_dataset = dataset.load_chart_dataset(split = "test")
        if args.icl:
            train_dataset = dataset.load_chart_dataset(split = "train")

    elif args.dataset_name == "plotqa":
        dataset = PlotQADataset("plotqa", processor=processor)
        test_dataset = dataset.load_plotqa_dataset(split = "test")
        test_dataset = test_dataset.shuffle(seed=seed)
        test_dataset = test_dataset.select(range(5000))

        if args.icl:
            train_dataset = dataset.load_plotqa_dataset(split = "train")
            train_dataset = train_dataset.shuffle(seed=seed)
            train_dataset = train_dataset.select(range(50000))

    elif args.dataset_name == "figqa":
        dataset = ChartDataset("figqa", processor=processor)
        test_dataset = dataset.load_chart_dataset(split = "test")
        if args.icl:
            train_dataset = dataset.load_chart_dataset(split = "train")

    elif args.dataset_name == "charttotext":
        dataset = ChartToTextDataset("chart2text", processor=processor)
        test_dataset = dataset.load(split = "test")
        if args.icl:
            train_dataset = dataset.load(split = "train")

    elif args.dataset_name == "evochart":
        dataset = ChartDataset("evochart", processor=processor)
        test_dataset = dataset.load_chart_dataset(split = "test")

    elif args.dataset_name == "chartllama":
        dataset = ChartDataset("chartllama", processor=processor)
        test_dataset = dataset.load_chart_dataset(split = "test")

    elif args.dataset_name == "chartbench":
        dataset = ChartDataset("chartbench", processor=processor)
        test_dataset = dataset.load_chart_dataset(split = "test").shuffle(seed=seed).select(range(5000))

    elif args.dataset_name == "chartx":
        dataset = ChartDataset("chartx", processor=processor)
        test_dataset = dataset.load_chart_dataset(split = "test")
    
    # Load the model and processor
    if args.mode == "eval":
        blocks = 4 if args.cot else 1 # 1 is Direct Prompting, 2 is typical COT, 4 is COT, 4 is GRPO COT 
        logging.info("Blocks:", blocks)
        # SFT adapter
        if args.sft_lora:
            # sft_model_path = "/mnt/home/sanchit/Qwen2-VL-Finetune/output/sft-"+str(seed)+"/"
            sft_model_path = "/mnt/home/sanchit/Qwen2-VL-Finetune/output/q2-large-sft-"+str(seed)+"/"
            from transformers import  Qwen2_5_VLForConditionalGeneration, Qwen2_5_VLProcessor
            model = Qwen2_5_VLForConditionalGeneration.from_pretrained(sft_model_path, device_map="auto", local_files_only=True)
            model.eval()
            logging.info("Loaded model with SFT adapters from {}".format(sft_model_path))

        # DPO adapter
        if args.dpo_lora:
            # adapter_path = "qwen-7b-train-chartqa-dpo-no-sft-v1-hardneg-beta-0.3-test/checkpoint-7000"
            # adapter_path = "qwen-7b-train-chartqa-dpo-no-sft-v1-hardneg-beta-0.3-ipo/checkpoint-7000"
            # adapter_path = "qwen-7b-train-chartqa-dpo-no-sft-v1-hardneg-beta-0.3-hinge/checkpoint-7000"
            # adapter_path = "qwen-7b-train-chartqa-dpo-no-sft-v1-hardneg-beta-0.3-sppo_hard/checkpoint-7000"
            # adapter_path = "qwen-7b-train-chartqa-dpo-no-sft-v1-hardneg-beta-0.3-apo_zero/checkpoint-7000"
            # adapter_path = args.dpo_lora

            # adapter_path = "qwen-7b-train-chartqa-dpo-no-sft-v2-ocr-tabular-ocr-qwen-data-high-caphinge/checkpoint-15000"
            # adapter_path = "qwen-2b-train-chartqa-dpo-no-sft-v2-ocr-tabular-ocr-qwen-data-high-caphinge/checkpoint-8000"
            
            
            # adapter_path = "qwen-7b-train-chartqa-dpo-base-ocr-tabular-rationaleshinge/checkpoint-21018"
            # adapter_path = "qwen-7b-train-chartqa-dpo-base-ocr-tabular-rationales-unicharthinge/checkpoint-28500"

            # adapter_path = "qwen-7b-train-chartqa-dpo-no-sft-v1-tabularhinge/checkpoint-14490"

            # Data gen
            # adapter_path = "qwen-2b-train-chartqa-dpo-base-ocr-tabular-rationaleshinge/checkpoint-21018"
            # Unichart tables
            adapter_path = "qwen-2b-train-chartqa-dpo-base-ocr-tabular-rationales-unicharthinge/checkpoint-65000"
        
            model = PeftModel.from_pretrained(model, adapter_path)
            model = model.merge_and_unload()

            logging.info("Loaded model with DPO adapters from {}".format(adapter_path))
        
        if args.grpo_lora:
            from peft import PeftModel
            # Use local checkpoint from training or download from HF
            if not args.hard:
                # For regular Chart-RVR-3B (6K dataset)
                grpo_path = "./grpo-start-ckpts/qwen2-5-3b-prm-large-train-v2-"+str(seed)
            else:
                # For Chart-RVR-3B-Hard (30K dataset)
                grpo_path = "./grpo-start-ckpts/qwen2-5-3b-prm-large-train-v2-"+str(seed)

            # Check if local checkpoint exists
            if os.path.exists(grpo_path):
                # Find latest checkpoint
                import glob
                checkpoints = sorted(glob.glob(os.path.join(grpo_path, "checkpoint-*")),
                                   key=lambda x: int(x.split('-')[-1]))
                if checkpoints:
                    final_checkpoint = checkpoints[-1]
                    logging.info(f"Loading local GRPO checkpoint: {final_checkpoint}")
                    model = PeftModel.from_pretrained(model, final_checkpoint)
                    logging.info(f"✓ Loaded GRPO LoRA adapters from {final_checkpoint}")
                else:
                    logging.error("No checkpoints found! Train the model first or download from HF.")
                    exit(1)
            else:
                # Download from HuggingFace
                logging.info("Local checkpoint not found. Attempting to download from HuggingFace...")
                hf_model_id = "sanchit97/chart-rvr-3b" if not args.hard else "sanchit97/chart-rvr-hard-3b"
                logging.info(f"Downloading: {hf_model_id}")
                model = PeftModel.from_pretrained(model, hf_model_id)
                logging.info(f"✓ Loaded GRPO adapters from HuggingFace: {hf_model_id}")

            model.eval()


        em_correct, ra_correct, tot_bleuscore, total = 0, 0, 0, 0

        aug_correct, aug_total = 0, 0
        human_correct, human_total = 0, 0


        wrongs = []
        pref_data = []
        
        logging.info("Starting evaluation on {} samples".format(len(test_dataset)))
        logging.info("Using CoT: {}".format(args.cot))


        loader = dataset.create_loader(test_dataset, bsz=1)

        if args.icl:
            path = "./icl-examples/"+args.dataset_name+"-icl_samples.pkl"
            if os.path.exists(path):
                icl_samples = pickle.load(open(path, 'rb')) # load in the ICL examples : list of [img, text, answer]
                logging.info("Loaded ICL examples from {}".format(path))
            else:
                icl_samples = select_icl_samples(train_dataset, k=5)
                logging.info("Selected ICL examples")
                pickle.dump(icl_samples, open(path, 'wb'))
        
        idx = 0
        for batch in tqdm.tqdm(loader):
            if args.icl:
                pred, rationale = get_vlm_output(model, processor, batch[0], batch[1], args.cot, icl_samples, blocks)
            else:
                if args.vlm_name in ["qwen-2b"]:
                    logging.info("Using explicit model device setting")
                    pred, rationale = get_vlm_output(model, processor, batch[0], batch[1], args.cot, model_device="cuda", blocks = blocks)
                else:
                    logging.info("Using automatic model device setting")
                    pred, rationale = get_vlm_output(model, processor, batch[0], batch[1], args.cot, blocks = blocks)
            # print(batch)
            if args.vlm_name in ["chart-gemma"]:
                print(pred[0])
                print(batch[2][0])
                print("#####")
            else:
                # print(pred)
                # print(batch[2])
                print(rationale[0])
                print("#####")
            # breakpoint()
            # TODO: Understand why this takes so long (and optimize)
            bleu_score = 0
            # for i in range(len(pred)):
            #     bleu_score += sacrebleu.corpus_bleu([batch[2][i]], [[pred[i]]]).score
            tot_bleuscore += bleu_score
            # Exact match
            em_correct += exact_match(batch[2], pred)
            # Realaxed accuracy
            if args.dataset_name == "chartqapro":
                ra = relaxed_accuracy(batch[2],pred, True)
            else:
                ra = relaxed_accuracy(batch[2],pred)

            if args.dataset_name == "chartqa" or args.dataset_name == "chartqa-src":
                # Augmented accuracy
                for i in range(len(batch[3])):
                    if batch[3][i]==1:
                        aug_total += 1
                        if ra[1][i]==1:
                            aug_correct += 1
                        

                # Human accuracy
                for i in range(len(batch[3])):
                    if batch[3][i]==0:
                        human_total += 1
                        if ra[1][i]==1:
                            human_correct += 1


            ra_correct += ra[0]

            total += len(batch[0])

            # print("EM: ", em_correct/total)
            # print("Relaxed Accuracy: ", ra_correct/total)
            
            # print("Aug Accuracy:", aug_correct/aug_total ) if aug_total>0 else print("Aug Accuracy: No aug samples")
            # print("Human Accuracy:", human_correct/human_total ) if human_total>0 else print("Human Accuracy: No human samples")
            # print("Average Accuracy:", 0.5*(aug_correct/aug_total + human_correct/human_total)) if aug_total>0 and human_total>0 else print("Average Accuracy: NA")

            # for img in batch[0]:
            #     img.save("./junkimage/"+str(idx)+".png")
            #     idx+=1
            # breakpoint()
            # print("BLEU Score: ", tot_bleuscore/total)
            # print(batch)
        
    if args.mode == "sft":
        os.environ["WANDB_CONSOLE"] = "wrap" 
        wandb.init(project="chartrl", entity="chartrl")

        logging.info("Loaded model, train and eval datasets")
        logging.info("Using:", model.config._attn_implementation)

        bnb_config = BitsAndBytesConfig(
                    load_in_4bit=True, 
                    bnb_4bit_use_double_quant=True, 
                    bnb_4bit_quant_type="nf4", 
                    bnb_4bit_compute_dtype=torch.bfloat16)
        
        
        peft_config = LoraConfig(
                    lora_alpha=256,
                    lora_dropout=0.05,
                    r=256,
                    bias="none",
                    target_modules = target_modules,
                    task_type="CAUSAL_LM",)


        peft_model = get_peft_model(model, peft_config)
        print(peft_model.print_trainable_parameters())

        logging.info("Loaded model+LORA adapters")

        training_args = SFTConfig(
            output_dir=args.vlm_name+"-sft-train"+args.dataset_name,  # Directory to save the model
            num_train_epochs=3,  # Number of training epochs
            per_device_train_batch_size=4,  # Batch size for training
            per_device_eval_batch_size=4,  # Batch size for evaluation
            gradient_accumulation_steps=4,  # Steps to accumulate gradients
            gradient_checkpointing=True,  # Enable gradient checkpointing for memory efficiency
            # Optimizer and scheduler settings
            lr_scheduler_type="linear",
            optim="adamw_torch_fused",  # Optimizer type
            learning_rate=5e-6,  # Learning rate for training
            # Logging and evaluation
            logging_steps=10,  # Steps interval for logging
            eval_steps=500,  # Steps interval for evaluation
            eval_strategy="steps",  # Strategy for evaluation
            save_strategy="steps",  # Strategy for saving the model
            save_steps=500,  # Steps interval for saving
            metric_for_best_model="eval_loss",  # Metric to evaluate the best model
            greater_is_better=False,  # Whether higher metric values are better
            load_best_model_at_end=True,  # Load the best model after training
            # Mixed precision and gradient settings
            bf16=True,  # Use bfloat16 precision
            tf32=True,  # Use TensorFloat-32 precision
            max_grad_norm=0.3,  # Maximum norm for gradient clipping
            # warmup_ratio=0.2,  # Ratio of total steps for warmup
            warmup_steps=1000,  # Number of warmup steps
            # Hub and reporting
            push_to_hub=False,  # Whether to push model to Hugging Face Hub
            report_to="wandb" ,  # Reporting tool for tracking metrics
            # Gradient checkpointing settings
            gradient_checkpointing_kwargs={"use_reentrant": False},  # Options for gradient checkpointing
            # Dataset configuration
            dataset_text_field="",  # Text field in dataset
            dataset_kwargs={"skip_prepare_dataset": True},  # Additional dataset options
            # max_seq_length=1024  # Maximum sequence length for input
        )

        training_args.remove_unused_columns = False  # Keep unused columns in dataset
        # training_args.dataloader_num_workers = 4  # Number of workers for data loading

        logging.info("Training arguments set up")

        trainer = SFTTrainer(
            model=peft_model,
            args=training_args,
            train_dataset=train_dataset,
            eval_dataset=eval_dataset,
            # data_collator=dataset.train_collate_fn_plotqa,
            data_collator=dataset.train_collate_fn_chartqa,
            # data_collator=dataset.train_collate_fn_charttotext,
            peft_config=peft_config,
            # tokenizer=processor.tokenizer,
            tokenizer=processor,

        )

        
        logging.info("SFT Trainer initialized")
        trainer.train()
        logging.info("Training completed, saving output model")
        trainer.save_model(training_args.output_dir)
        logging.info("Model saved to {}".format(training_args.output_dir))


    if args.mode == "dpo":
        os.environ["WANDB_CONSOLE"] = "wrap" 
        wandb.init(project="chartrl", entity="chartrl")

        if args.sft_lora:
            # adapter_path = "llava-1.6-train-plotqa-v0"
            # adapter_path = "/mnt/home/sanchit/Qwen2-VL-Finetune/output/chartqa_lora-v0"
            # adapter_path = "/mnt/home/sanchit/Qwen2-VL-Finetune/output/chartqa_lora-v0"
            # adapter_path = "/mnt/home/sanchit/Qwen2-VL-Finetune/output/chartqa_lora-v0"
            adapter_path = "llava-1.6-train-chartqa"
            model = PeftModel.from_pretrained(model, adapter_path)
            model = model.merge_and_unload()
            logging.info("Loaded model with SFT adapters from {}".format(adapter_path))

        pref_dataset = dataset.load_pref_data()
        eval_dataset = dataset.load_pref_data().select(range(512))

        lossname = "hinge"
        logging.info("Loaded model, pref and eval datasets")
        logging.info("Using: "+lossname)
                    
        dpo_peft_config = LoraConfig(
                    lora_alpha=256,
                    lora_dropout=0.05,
                    r=256,
                    bias="none",
                    target_modules = target_modules
                    )
        peft_model = get_peft_model(model, dpo_peft_config)
        print(peft_model.print_trainable_parameters())
        peft_model.config.use_cache = False
        logging.info("Loaded model+LORA adapters")

        training_args = DPOConfig(
        # output_dir=model_name+"-train-chartqa-dpo-sft-v1-hardneg-beta-0.3-test",  # Directory to save the model
        # output_dir=args.vlm_name+"-train-chartqa-dpo-base-ocr-tabular-rationales-unichart"+lossname,  # Directory to save the model
        # output_dir=args.vlm_name+"-dpo-sft-v2-ocr-tabular-high-cap-"+lossname,  # Directory to save the model
        output_dir=args.vlm_name+"random-test"+lossname,  # Directory to save the model
        bf16=True,
        gradient_checkpointing=True,
        per_device_train_batch_size=8,
        gradient_accumulation_steps=2,
        num_train_epochs=3,
        dataset_num_proc=32,  # tokenization will use 32 processes
        dataloader_num_workers=32,  # data loading will use 32 workers
        logging_steps=20,
        eval_strategy="steps",
        eval_steps=1000,
        beta=0.3,  # DPO beta parameter (default: 0.1)
        loss_type = lossname, # try different stuff
        )
        trainer = DPOTrainer(
            peft_model,
            ref_model=None,  # not needed when using peft
            args=training_args,
            train_dataset=pref_dataset,
            eval_dataset=eval_dataset,
            processing_class = processor,
            peft_config=dpo_peft_config,
        )

        trainer.train()


    if args.mode in ["grpo", "psr", "nsr", "w-reinforce"]:
        # Setup and imports
        os.environ["WANDB_CONSOLE"] = "wrap"

        # Initialize wandb with enhanced config tracking
        wandb.init(
            project="chartrl-nsr",
            entity="chartrl",
            name=f"{args.mode}-{args.vlm_name}-{args.dataset_name}-{args.subset_size or 'full'}-{seed}",
            config={
                "mode": args.mode,
                "model": args.vlm_name,
                "dataset": args.dataset_name,
                "subset_size": args.subset_size,
                "num_epochs": args.num_epochs,
                "num_generations": args.num_generations,
                "batch_size": args.batch_size,
                "learning_rate": 1e-5,
                "seed": seed,
                "lambda_psr": args.lambda_psr if args.mode == "w-reinforce" else None,
                "reward_threshold": args.reward_threshold if args.mode in ["psr", "nsr", "w-reinforce"] else None,
                "gradient_checkpointing": not args.disable_gradient_checkpointing,
            },
            tags=[args.mode, args.dataset_name, f"samples_{args.subset_size or 'full'}"]
        )

        from trl import (GRPOConfig, GRPOTrainer, get_peft_config)
        from grpo_utils import format_reward,\
             accuracy_reward,\
             length_think_reward,\
             num_token_reward,\
             chart_type_reward,\
             table_style_reward,\
             process_style_reward


        blocks = 4

        def _resize_up(img):
            from PIL import Image as PILImage
            MIN_PIXELS = 320 * 28 * 28            # 1 003 520
            # MAX_PIXELS = 16384 * 28 * 28           # 12 843 776
            MAX_PIXELS = 320 * 28 * 28           # 12 843 776 (about 500x500)

            img = img.convert("RGB")
            w, h = img.size
            p = w * h
            if MIN_PIXELS <= p <= MAX_PIXELS:
                return img
            tgt_p  = max(min(p, MAX_PIXELS), MIN_PIXELS)
            scale  = (tgt_p / p) ** 0.5
            new_wh = (int(w * scale), int(h * scale))
            return img.resize(new_wh, PILImage.BICUBIC)

        def _grpo_format_data(example):
                from prompts import SYSTEM_PROMPT_TEMPLATES
                SYSTEM_PROMPT = SYSTEM_PROMPT_TEMPLATES[blocks]

                # TRL 0.20+ expects conversation format for VLMs
                conversation = [
                    {"role": "system", "content": SYSTEM_PROMPT},
                    {
                        "role": "user",
                        "content": [
                            {"type": "image"},
                            {"type": "text", "text": example["query"]},
                        ],
                    },
                ]

                return {
                    "prompt": conversation,  # Conversation format for TRL 0.20+
                    "images": [_resize_up(example["image"])],  # Note: 'images' not 'image'
                    # Include fields needed by reward functions
                    "label": example.get("label", ""),
                    "table": example.get("table", None),
                    "chart_type": example.get("chart_type", ""),
                    "reasoning": example.get("reasoning", ""),
                }

        # =================================================================
        # LOAD TRAINING DATASET FROM HUGGINGFACE
        # =================================================================
        from datasets import load_from_disk

        grpo_dataset_path = "/grpo-chartrvr-train"

        # Check if dataset exists locally (from previous download)
        if os.path.exists(cache_dir + grpo_dataset_path):
            logging.info(f"Loading dataset from disk: {cache_dir + grpo_dataset_path}")
            full_dataset = load_from_disk(cache_dir + grpo_dataset_path)
            train_dataset = full_dataset["train"]
        else:
            # Download from HuggingFace
            logging.info("Dataset not found locally. Downloading from HuggingFace: sanchit97/chart-rvr-grpo-train")
            from datasets import load_dataset
            full_dataset = load_dataset("sanchit97/chart-rvr-grpo-train", cache_dir=cache_dir)
            # Save for future use
            full_dataset.save_to_disk(cache_dir + grpo_dataset_path)
            logging.info(f"Dataset saved to: {cache_dir + grpo_dataset_path}")
            train_dataset = full_dataset["train"]

        logging.info(f"Loaded {len(train_dataset)} training samples")

        # Use subset if specified via --subset-size argument
        if args.subset_size is not None:
            train_dataset = train_dataset.select(range(min(args.subset_size, len(train_dataset))))
            logging.info(f"✓ Using subset: {len(train_dataset)} samples (--subset-size={args.subset_size})")
        else:
            logging.info(f"✓ Using full dataset: {len(train_dataset)} samples")

        # Format dataset for GRPO training
        # Use Python list directly to avoid Arrow serialization issues
        logging.info("Formatting dataset as Python list...")
        grpo_train_dataset = []

        from tqdm import tqdm
        for example in tqdm(train_dataset, desc="Formatting training data"):
            formatted = _grpo_format_data(example)
            grpo_train_dataset.append(formatted)

        logging.info(f"Training dataset formatted. Total samples: {len(grpo_train_dataset)}")
        logging.info(f"Sample has {len(grpo_train_dataset[0]['prompt'])} messages")

        # =================================================================
        # SKIP EVALUATION DATASET - WILL EVAL AFTER TRAINING
        # =================================================================
        logging.info("Skipping evaluation during training")
        grpo_eval_dataset = None
        logging.info("✓ Training dataset ready for GRPO")


        # start from an SFT checkpoint
        # sft_model_path = "/mnt/home/sanchit/Qwen2-VL-Finetune/output/sft-2.5-3b-chartqa-rationales/checkpoint-200"
        # from transformers import  Qwen2_5_VLForConditionalGeneration, Qwen2_5_VLProcessor
        # model = Qwen2_5_VLForConditionalGeneration.from_pretrained(sft_model_path)
        # logging.info("Loaded model with SFT adapters from {}".format(sft_model_path))

        # =================================================================
        # LORA CONFIGURATION FOR MEMORY EFFICIENCY
        # =================================================================
        from peft import LoraConfig, get_peft_model

        logging.info("Applying LoRA adapters for memory-efficient GRPO training...")
        grpo_peft_config = LoraConfig(
            r=8,  # Low rank for memory efficiency (vs 256 for full training)
            lora_alpha=16,  # 2 * rank for optimal training speed
            lora_dropout=0.05,
            bias="none",
            target_modules=["q_proj", "k_proj", "v_proj", "o_proj", "up_proj", "down_proj", "gate_proj"],  # All weight matrices
            task_type="CAUSAL_LM",
        )

        model = get_peft_model(model, grpo_peft_config)
        logging.info("✓ LoRA adapters applied successfully")
        print("=" * 80)
        print("TRAINABLE PARAMETERS:")
        print(model.print_trainable_parameters())
        print("=" * 80)

        # Log configuration
        logging.info("=" * 80)
        if args.mode in ["psr", "nsr", "w-reinforce"]:
            logging.info(f"{args.mode.upper()} TRAINING CONFIGURATION:")
        else:
            logging.info("GRPO TRAINING CONFIGURATION:")
        logging.info(f"  Training mode: {args.mode}")
        logging.info(f"  Training samples: {len(grpo_train_dataset)}")
        logging.info(f"  Epochs: {args.num_epochs}")
        logging.info(f"  Batch size: {args.batch_size}")
        logging.info(f"  Generations per sample: {args.num_generations}")
        logging.info(f"  Gradient checkpointing: {not args.disable_gradient_checkpointing}")
        if args.mode == "w-reinforce":
            logging.info(f"  Lambda PSR: {args.lambda_psr}")
            logging.info(f"  Reward threshold: {args.reward_threshold}")
        elif args.mode in ["psr", "nsr"]:
            logging.info(f"  Reward threshold: {args.reward_threshold}")
        logging.info("=" * 80)

        # Set output directory based on training mode
        mode_suffix = f"-{args.mode}" if args.mode != "grpo" else ""
        output_dir = f"grpo-start-ckpts/{args.vlm_name}-prm-large-train-v2{mode_suffix}-{str(seed)}"

        training_args = GRPOConfig(
        output_dir = output_dir,
        bf16=True,
        remove_unused_columns = False,
        per_device_train_batch_size=args.batch_size,  # Configurable via --batch-size
        gradient_accumulation_steps=2,  # Effective batch size = batch_size * 2
        num_train_epochs=args.num_epochs,  # Configurable via --num-epochs

        # ===== ENHANCED LOGGING =====
        logging_dir=f"{output_dir}/logs",  # Save logs to checkpoint directory
        logging_steps=10,  # Log every 10 steps (more frequent than default 50)
        logging_first_step=True,  # Log first step
        report_to="wandb",  # Report to Weights & Biases

        # ===== ENHANCED CHECKPOINTING =====
        save_strategy="steps",  # Save checkpoints every N steps
        save_steps=50,  # Save checkpoint every 50 steps
        save_total_limit=3,  # Keep only last 3 checkpoints (save disk space)
        save_safetensors=True,  # Use safetensors format (safer and faster)

        # ===== GRPO SPECIFIC =====
        max_prompt_length = 4096,  # Restored to original (LoRA saves memory)
        eval_strategy="no",  # Disabled - no eval during training
        eval_steps=500,  # Ignored when eval_strategy="no"
        max_completion_length = 768,  # Restored to original (LoRA saves memory)
        num_generations = args.num_generations,  # Configurable via --num-generations
        learning_rate = 1e-5,  # LoRA requires higher LR than full fine-tuning (8e-7)
        beta = 0.0,  # Disable reference model for VLM support (reduces memory)
        gradient_checkpointing=not args.disable_gradient_checkpointing,  # Configurable via --disable-gradient-checkpointing

        # ===== RESUMABILITY =====
        # NOTE: Resumption is now handled explicitly in code (see lines 823-847)
        # resume_from_checkpoint=True,  # Removed - handled explicitly below
        load_best_model_at_end=False,  # Don't load best (no eval)
        )

        # =================================================================
        # NSR TRAINING MODE: Apply reward filtering based on mode
        # =================================================================
        base_reward_funcs = [format_reward, accuracy_reward, length_think_reward, num_token_reward, chart_type_reward, table_style_reward, process_style_reward]

        if args.mode in ["psr", "nsr", "w-reinforce"]:
            # Import training mode filters
            from trainers.psr_trainer import psr_reward_filter
            from trainers.nsr_trainer import nsr_reward_filter
            from trainers.weighted_reinforce_trainer import weighted_reinforce_reward_filter

            # Create filtered reward function wrapper with enhanced logging
            step_counter = [0]  # Mutable counter for logging

            def create_filtered_reward_func(base_funcs, mode, lambda_psr, reward_threshold):
                """Wrapper that applies reward filtering based on training mode"""
                def filtered_reward_func(completions, **kwargs):
                    # Compute base rewards (sum of all reward functions)
                    total_rewards = None
                    for reward_func in base_funcs:
                        rewards = reward_func(completions, **kwargs)
                        if total_rewards is None:
                            total_rewards = rewards
                        else:
                            total_rewards = [t + r for t, r in zip(total_rewards, rewards)]

                    # Apply mode-specific filtering
                    if mode == "psr":
                        filtered_rewards = psr_reward_filter(total_rewards, reward_threshold)
                        pos_count = sum(1 for r in filtered_rewards if r > 0)
                        logging.info(f"PSR [Step {step_counter[0]}]: {pos_count}/{len(filtered_rewards)} positive samples | Avg reward: {sum(filtered_rewards)/len(filtered_rewards):.3f}")
                        # Log to wandb
                        if step_counter[0] % 10 == 0:
                            wandb.log({
                                "psr/positive_samples": pos_count,
                                "psr/positive_ratio": pos_count / len(filtered_rewards),
                                "psr/avg_reward": sum(filtered_rewards) / len(filtered_rewards),
                            }, step=step_counter[0])
                    elif mode == "nsr":
                        filtered_rewards = nsr_reward_filter(total_rewards, reward_threshold)
                        neg_count = sum(1 for r in filtered_rewards if r < 0)
                        logging.info(f"NSR [Step {step_counter[0]}]: {neg_count}/{len(filtered_rewards)} negative samples | Avg reward: {sum(filtered_rewards)/len(filtered_rewards):.3f}")
                        # Log to wandb
                        if step_counter[0] % 10 == 0:
                            wandb.log({
                                "nsr/negative_samples": neg_count,
                                "nsr/negative_ratio": neg_count / len(filtered_rewards),
                                "nsr/avg_reward": sum(filtered_rewards) / len(filtered_rewards),
                            }, step=step_counter[0])
                    elif mode == "w-reinforce":
                        filtered_rewards = weighted_reinforce_reward_filter(total_rewards, lambda_psr, reward_threshold)
                        pos = sum(1 for r in total_rewards if r >= reward_threshold)
                        neg = sum(1 for r in total_rewards if r < reward_threshold)
                        logging.info(f"W-REINFORCE [Step {step_counter[0]}]: {pos} pos (λ={lambda_psr}) + {neg} neg (λ=1.0) | Avg reward: {sum(filtered_rewards)/len(filtered_rewards):.3f}")
                        # Log to wandb
                        if step_counter[0] % 10 == 0:
                            wandb.log({
                                "w_reinforce/positive_samples": pos,
                                "w_reinforce/negative_samples": neg,
                                "w_reinforce/pos_neg_ratio": pos / (neg + 1e-6),
                                "w_reinforce/avg_reward": sum(filtered_rewards) / len(filtered_rewards),
                            }, step=step_counter[0])
                    else:
                        filtered_rewards = total_rewards

                    step_counter[0] += 1
                    return filtered_rewards

                return filtered_reward_func

            # Use filtered reward function
            reward_funcs_to_use = [create_filtered_reward_func(base_reward_funcs, args.mode, args.lambda_psr, args.reward_threshold)]

            logging.info(f"✓ {args.mode.upper()} reward filtering enabled")
            if args.mode == "psr":
                logging.info("  → Training only on POSITIVE samples (correct responses)")
                logging.info("  → Expected: High Pass@1, Lower Pass@k at large k")
            elif args.mode == "nsr":
                logging.info("  → Training only on NEGATIVE samples (incorrect responses)")
                logging.info("  → Expected: High Pass@k across all k, preserves diversity")
            elif args.mode == "w-reinforce":
                logging.info(f"  → Weighted training: {args.lambda_psr}·PSR + NSR")
                logging.info("  → Expected: Best Pass@1 and Pass@k overall")

        else:
            # Standard GRPO mode - use all reward functions separately
            reward_funcs_to_use = base_reward_funcs
            logging.info("✓ Standard GRPO training (no reward filtering)")

        trainer = GRPOTrainer(
            model=model,
            args=training_args,
            reward_funcs=reward_funcs_to_use,
            train_dataset=grpo_train_dataset,
            eval_dataset=None,  # Skip eval during training
            processing_class=processor,
        )

        # ===================================================================
        # FIX: Explicitly check for and resume from checkpoints
        # ===================================================================
        import glob

        checkpoint_to_resume = None

        if os.path.exists(output_dir):
            # Find all existing checkpoints
            checkpoints = sorted(
                glob.glob(os.path.join(output_dir, "checkpoint-*")),
                key=lambda x: int(x.split('-')[-1])
            )

            if checkpoints:
                checkpoint_to_resume = checkpoints[-1]
                logging.info("=" * 80)
                logging.info(f"✓ FOUND EXISTING CHECKPOINT: {checkpoint_to_resume}")
                logging.info(f"✓ Will resume training from step {checkpoint_to_resume.split('-')[-1]}")
                logging.info("=" * 80)
            else:
                logging.info("No existing checkpoints found. Starting fresh training.")

        # Start or resume training
        trainer.train(resume_from_checkpoint=checkpoint_to_resume)