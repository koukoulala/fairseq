# Copyright (c) Microsoft Corporation.
# Licensed under the MIT license.


lg=$1          # supervised lanugage for finetuning [en]
NGPU=$2        # num of GPUs to use
CODE_ROOT=$3   # path/to/code_root
MODEL_DIR=$4   # path/to/model_dir
OUTPUT_DIR=$5  # output dir to save checkpoints, decodings, etc 
DATA_ROOT=$6   # path/to/XGLUE/NTG  


PRETRAIN=$MODEL_DIR/mbart.cc25.v2

DATA_BIN=$DATA_ROOT/$lg.spm.dest

langs=ar_AR,cs_CZ,de_DE,en_XX,es_XX,et_EE,fi_FI,fr_XX,gu_IN,hi_IN,it_IT,ja_XX,kk_KZ,ko_KR,lt_LT,lv_LV,my_MM,ne_NP,nl_XX,ro_RO,ru_RU,si_LK,tr_TR,vi_VN,zh_CN

fairseq-train $DATA_BIN \
  --encoder-normalize-before --decoder-normalize-before \
  --arch mbart_large --layernorm-embedding \
  --task translation_from_pretrained_bart \
  --source-lang src --target-lang tgt \
  --source-language en_XX --target-language en_XX \
  --criterion label_smoothed_cross_entropy --label-smoothing 0.2 \
  --optimizer adam --adam-eps 1e-06 --adam-betas '(0.9, 0.98)' \
  --lr-scheduler polynomial_decay --lr 3e-05 --warmup-updates 2500 --total-num-update 40000 \
  --dropout 0.3 --attention-dropout 0.1 --weight-decay 0.0 \
  --max-tokens 1024 --update-freq 2 \
  --save-interval 1 --save-interval-updates 5000 --keep-interval-updates 10 --no-epoch-checkpoints \
  --seed 222 --log-format simple --log-interval 2 \
  --restore-file $PRETRAIN \
  --reset-optimizer --reset-meters --reset-dataloader --reset-lr-scheduler \
  --langs $langs \
  --ddp-backend no_c10d