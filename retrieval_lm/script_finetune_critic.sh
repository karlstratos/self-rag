DATA_PATH=$1
MODEL_SAVE_DIR=$2
CACHE_DIR=$3

#cd data_creation
torchrun --nproc_per_node=8 \
  --master_port=2568 train_special_tokens.py \
  --model_name_or_path meta-llama/Llama-2-7b-hf \
  --data_path $DATA_PATH \
  --bf16  True \
  --output_dir $MODEL_SAVE_DIR \
  --num_train_epochs 3  \
  --per_device_train_batch_size 1 --per_device_eval_batch_size 1 \
  --gradient_accumulation_steps 8 \
  --evaluation_strategy "no" \
  --save_strategy "steps" \
  --save_steps 300 \
  --save_total_limit 1 \
  --learning_rate 2e-5 \
  --weight_decay 0. \
  --warmup_ratio 0.01 \
  --lr_scheduler_type "cosine" \
  --logging_steps 10 \
  --fsdp "full_shard auto_wrap" \
  --cache_dir $CACHE_DIR