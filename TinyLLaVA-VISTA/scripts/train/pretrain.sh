#!/bin/bash


DATA_PATH=LLaVA-Pretrain/blip_laion_cc_sbu_558k_fim.json
IMAGE_PATH=LLaVA-Pretrain/images

LLM_VERSION=microsoft/phi-2 # llm path in huggingface
VT_VERSION=google/siglip-so400m-patch14-384 #vision tower path in huggingface
ORIGIN_VT_VERSION=google/siglip-so400m-patch14-384 #origin vision tower path in huggingface
ORIGIN_LLM_VERSION=microsoft/phi-2 #origin llm path in huggingface
VT_VERSION2="" #if you are not using mof vision tower, keep it empty
CN_VERSION=mlp2x_gelu #connector type, other options are: qformer, resampler, etc
CONV_VERSION=phi #chat template, other options are: phi, llama, gemmma, etc
VERSION=base #experiment name for recording different runnings
TRAIN_RECIPE=common #training recipes, other options are: lora, qlora
MODEL_MAX_LENGTH=3072 #max model length for llm
VT_VARIANT="${ORIGIN_VT_VERSION#*/}"
LLM_VARIANT="${ORIGIN_LLM_VERSION#*/}"
MODEL_NAME=tiny-llava-${LLM_VARIANT}-${VT_VARIANT}-${VERSION}-pretrain-maea-mt-l2-correct
OUTPUT_DIR=output/${MODEL_NAME}

nohup deepspeed tinyllava/train/train.py \
    --deepspeed ./scripts/zero2.json \
    --data_path  $DATA_PATH\
    --image_folder $IMAGE_PATH \
    --is_multimodal True \
    --conv_version pretrain \
    --model_name_or_path $LLM_VERSION \
    --vision_tower $VT_VERSION \
    --vision_tower2 "$VT_VERSION2" \
    --connector_type $CN_VERSION \
    --mm_vision_select_layer -2 \
    --image_aspect_ratio square \
    --attn_implementation flash_attention_2 \
    --fp16 True \
    --training_recipe $TRAIN_RECIPE \
    --tune_type_llm frozen \
    --tune_type_vision_tower frozen \
    --tune_vision_tower_from_layer 0 \
    --tune_type_connector full \
    --output_dir ${OUTPUT_DIR} \
    --num_train_epochs 1 \
    --per_device_train_batch_size 32 \
    --per_device_eval_batch_size 4 \
    --gradient_accumulation_steps 1 \
    --evaluation_strategy "no" \
    --save_strategy "steps" \
    --save_steps 24000 \
    --save_total_limit 1 \
    --learning_rate 1e-3 \
    --weight_decay 0. \
    --warmup_ratio 0.03 \
    --lr_scheduler_type "cosine" \
    --logging_steps 1 \
    --tf32 False \
    --model_max_length $MODEL_MAX_LENGTH \
    --gradient_checkpointing True \
    --dataloader_num_workers 8 \
    --lazy_preprocess True \
    --report_to tensorboard \
    --tokenizer_use_fast False \
    --run_name ${MODEL_NAME} > logs/${MODEL_NAME}.out 2>&1 &

echo ${OUTPUT_DIR}
echo logs/${MODEL_NAME}.out
