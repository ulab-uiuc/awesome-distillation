docker run --name siqi_slime_opsd --gpus all --ipc=host --shm-size=64g \
  --ulimit memlock=-1 --ulimit stack=67108864 \
  -v /mnt/disk1_from_server2/siqizhu4/opsd_slime:/root/slime_siqi \
  -v /mnt/disk1_from_server2/siqizhu4/ray_tmp:/tmp/ray_siqi \
  -v /mnt/disk1_from_server2/siqizhu4/checkpoints:/root/checkpoints_siqi \
  -v /mnt/disk1_from_server2/siqizhu4/hf_cache:/root/.cache/huggingface \
  -w /root/slime_siqi \
  -it slimerl/slime:latest /bin/bash


docker run --name siqi_slime_opsd_v2 --gpus all --ipc=host --shm-size=64g \
  --ulimit memlock=-1 --ulimit stack=67108864 \
  -v /mnt/disk1_from_server2/siqizhu4/opsd_slime:/root/slime_siqi \
  -v /mnt/disk1_from_server2/siqizhu4/ray_tmp:/tmp/ray_siqi \
  -v /mnt/disk1_from_server2/siqizhu4/checkpoints:/root/checkpoints_siqi \
  -v /mnt/disk1_from_server2/siqizhu4/hf_cache:/root/.cache/huggingface \
  -w /root/slime_siqi \
  -it slimerl/slime:latest /bin/bash

/data/siqizhu4/opsd_slime
examples/on_policy_distillation/run-qwen3-1.7B-opsd_grpo-openthoughts_baseline.sh

docker run --name siqi_slime_opsd --gpus all --ipc=host -p 30000:30000 --shm-size=64g \
  --ulimit memlock=-1 --ulimit stack=67108864 \
  -v /data/siqizhu4/opsd_slime:/root/slime_siqi \
  -v /data/siqizhu4/ray_tmp:/tmp/ray_siqi \
  -v /data/siqizhu4/checkpoints:/root/checkpoints_siqi \
  -v /data/siqizhu4/hf_cache:/root/.cache/huggingface \
  -w /root/slime_siqi \
  -it slimerl/slime:latest /bin/bash



docker run --name siqi_slime_opsd --gpus all \
  --network host \
  --ipc=host --shm-size=64g \
  --ulimit memlock=-1 --ulimit stack=67108864 \
  -v /mnt/disk1_from_server2/siqizhu4/opsd_slime:/root/slime_siqi \
  -v /mnt/disk1_from_server2/siqizhu4/ray_tmp:/tmp/ray_siqi \
  -v /mnt/disk1_from_server2/siqizhu4/checkpoints:/root/checkpoints_siqi \
  -w /root/slime_siqi \
  -it slimerl/slime:latest /bin/bash

ray stop --force
pkill -9 ray
rm -rf /tmp/ray/*
rm -rf /tmp/ray_siqi/*

export HF_HOME=/mnt/disk1_from_server2/siqizhu4/hf_cache



docker exec -it siqi_slime_opsd bash

bash start.ps1

apt install iproute2 -y

export RAY_memory_usage_threshold=0.99
export RAY_memory_monitor_refresh_ms=0


export TRAIN_DATASET="open-thoughts/OpenThoughts-114k"
export TRAIN_CONFIG="metadata"
TRAIN_ANSWER_FORMAT=answer EVAL_ANSWER_FORMAT=answer bash examples/on_policy_distillation/run-qwen3-4B-opsd_pi.sh

TRAIN_ANSWER_FORMAT=boxed EVAL_ANSWER_FORMAT=boxed bash examples/on_policy_distillation/run-qwen3-4B-opsd_pi.sh


bash examples/on_policy_distillation/run-qwen3-4B-opsd_pi.sh


CUDA_VISIBLE_DEVICES=6,7 python -m sglang.launch_server \
    --model-path /root/checkpoints_siqi/models--Qwen--Qwen3-30B-A3B-Instruct-2507 \
    --host 0.0.0.0 \
    --port 30000 \
    --context-length 16384 \
    --tp-size 2


CUDA_VISIBLE_DEVICES=7,8 python -m sglang.launch_server \
    --model-path checkpoints/models--Qwen--Qwen3-30B-A3B-Instruct-2507 \
    --host 0.0.0.0 \
    --port 30000 \
    --context-length 65536 \
    --tp-size 2


export NCCL_P2P_DISABLE=1
CUDA_VISIBLE_DEVICES=4,5,8,9 python -m sglang.launch_server \
    --model-path /root/checkpoints_siqi/models--Qwen--Qwen3-30B-A3B-Instruct-2507 \
    --host 0.0.0.0 \
    --port 30000 \
    --context-length 32768 \
    --tp-size 4

base_url="http://172.22.224.251:30000/v1"


For server1: 
sed -n '1360,1370p' /sgl-workspace/sglang/python/sglang/srt/managers/tokenizer_manager.py

 然后把约 1365 行的：
  await self.send_to_scheduler.send_pyobj(obj)
  改为（去掉 await）：
  self.send_to_scheduler.send_pyobj(obj)

 或者用一行命令修复：
  sed -i 's/await
  self\.send_to_scheduler\.send_pyobj(obj)/self.send_to_scheduler.send_pyobj(obj)/' \
      /sgl-workspace/sglang/python/sglang/srt/managers/tokenizer_manager.py


# 删除data文件夹的git记录
git rm -r --cached data

export NCCL_P2P_DISABLE=1
export NCCL_IB_DISABLE=1



CUDA_VISIBLE_DEVICES=3,6,7,8 python3 -m sglang.launch_server --model-path /root/checkpoints_siqi/Qwen3-1.7B --port 30000 --host 0.0.0.0 --tp 1

CUDA_VISIBLE_DEVICES=7 python3 -m sglang.launch_server --model-path Qwen/Qwen3-8B --port 30001 --host 0.0.0.0 --tp 1
CUDA_VISIBLE_DEVICES=0,1 python3 -m sglang.launch_server --model-path /root/checkpoints_siqi/Qwen3-1.7B --port 30002 --host 0.0.0.0 --tp 2

CUDA_VISIBLE_DEVICES=4,6 python3 -m sglang.launch_server --model-path Qwen/Qwen2.5-7B-Instruct --port 30002 --host 0.0.0.0 --tp 1
CUDA_VISIBLE_DEVICES=0,1 python3 -m sglang.launch_server --model-path Qwen/Qwen2.5-7B-Instruct --port 30002 --host 0.0.0.0 --tp 1
CUDA_VISIBLE_DEVICES=1 python3 -m sglang.launch_server --model-path Qwen/Qwen3-8B --port 30001 --host 0.0.0.0 --tp 1

CUDA_VISIBLE_DEVICES=3,4 python3 -m sglang.launch_server --model-path Qwen/Qwen3-1.7B-step29 --port 30002 --host 0.0.0.0 --tp 2


CUDA_VISIBLE_DEVICES=5 python3 -m sglang.launch_server --model-path /root/checkpoints_siqi/Qwen3-1.7B --port 30002 --host 0.0.0.0 --tp 1
CUDA_VISIBLE_DEVICES=4 python3 -m sglang.launch_server --model-path Qwen/Qwen3-8B --port 30001 --host 0.0.0.0 --tp 1

CUDA_VISIBLE_DEVICES=4,5,7,8 python3 -m sglang.launch_server --model-path Qwen/Qwen3-8B --port 30001 --host 0.0.0.0 --tp 4


kill -9 $(lsof -t -i :30001)

python examples/on_policy_distillation/plot_token_winner_interactive.py \                                                             
    --input ./eval_math500_student_teacher_inference.jsonl \
    --output ./token_winner_interactive.html \
    --n-bins 200 \
    --max-requests 500

python examples/on_policy_distillation/plot_token_winner_interactive.py \
  --input ./eval_math500_student_teacher_inference.jsonl


python examples/on_policy_distillation/plot_token_winner_interactive.py \
  --input ./eval_math500_student_teacher_inference_s1.7t8b_noanswer_v2.jsonl \
  --output ./token_winner_interactive.html \
  --tokenizer Qwen/Qwen3-1.7B \
  --show-last-k-tokens 64

eval_math500_student_teacher_inference_s1.7t8b_same_as_student_b512.jsonl

python examples/on_policy_distillation/plot_token_winner_interactive.py \
  --input eval_math500_student_teacher_inference_s1.7t1.7b_answeronly_b512.jsonl \
  --output ./token_winner_interactive.html \
  --tokenizer Qwen/Qwen3-1.7B \
  --show-last-k-tokens 128


python examples/on_policy_distillation/plot_token_winner_interactive.py \
  --input eval_math500_student_teacher_inference_s1.7t8b_answeronly_disablethinking_b512.jsonl \
  --output ./token_winner_interactive.html \
  --tokenizer Qwen/Qwen3-1.7B \
  --show-last-k-tokens 64


python examples/on_policy_distillation/plot_token_winner_interactive.py \
  --input eval_math500_student_teacher_inference_s1.7t1.7b_answeronly_disablethinking_b512.jsonl \
  --output ./token_winner_interactive.html \
  --tokenizer Qwen/Qwen3-1.7B \
  --show-last-k-tokens 64


python examples/on_policy_distillation/plot_token_winner_interactive.py \
  --input ./eval_math500_student_teacher_inference_s1.7t8b_answeronly.jsonl \
  --output ./token_winner_interactive.html \
  --tokenizer Qwen/Qwen3-1.7B \
  --show-last-k-tokens 64


ps -o pid,ppid,user,tty,lstart,cmd -p 314845


CUDA_VISIBLE_DEVICES=1 python3 -m sglang.launch_server --model-path Qwen/Qwen3-8B --port 30000 --host 0.0.0.0 --tp 1  --mem-fraction-static  0.8   --watchdog-timeout 3600


cd /root/slime_siqi                                                                                                       
                                                                                                                            
python3 tools/convert_fsdp_to_hf.py \
  --input-dir /root/slime_siqi/output/Qwen3-1.7B_8B_opd_noanswer_dapo/iter_0000029 \
  --output-dir /root/checkpoints_siqi/Qwen3-1.7B_step29 \
  --origin-hf-dir /root/checkpoints_siqi/Qwen3-1.7B


CUDA_VISIBLE_DEVICES=7 python3 -m sglang.launch_server --model-path output/Qwen3-1.7B_opsd_masked_grpo_dapo_hf --port 30002 --host 0.0.0.0 --tp 1


