## Local Evaluation


### Server #14
CUDA_VISIBLE_DEVICES=0,1,2,3 VLLM_WORKER_MULTIPROC_METHOD=spawn vllm serve meta-llama/Llama-3-1-70B-Instruct --port 8000 -tp 4
CUDA_VISIBLE_DEVICES=4,5,6,7 VLLM_WORKER_MULTIPROC_METHOD=spawn vllm serve Qwen/Qwen2.5-72B-Instruct --port 8001 -tp 4

### Server #12
CUDA_VISIBLE_DEVICES=0 VLLM_WORKER_MULTIPROC_METHOD=spawn vllm serve Qwen/Qwen2.5-0.5B-Instruct --port 8000
CUDA_VISIBLE_DEVICES=1 VLLM_WORKER_MULTIPROC_METHOD=spawn vllm serve Qwen/Qwen2.5-1.5B-Instruct --port 8001
CUDA_VISIBLE_DEVICES=2 VLLM_WORKER_MULTIPROC_METHOD=spawn vllm serve Qwen/Qwen2.5-3B-Instruct --port 8002
CUDA_VISIBLE_DEVICES=3 VLLM_WORKER_MULTIPROC_METHOD=spawn vllm serve Qwen/Qwen2.5-7B-Instruct --port 8003
CUDA_VISIBLE_DEVICES=4,5 VLLM_WORKER_MULTIPROC_METHOD=spawn vllm serve Qwen/Qwen2.5-14B-Instruct --port 8004 -tp 2
CUDA_VISIBLE_DEVICES=6 VLLM_WORKER_MULTIPROC_METHOD=spawn vllm serve Qwen/Qwen2-7B-Instruct --port 8005
CUDA_VISIBLE_DEVICES=7 VLLM_WORKER_MULTIPROC_METHOD=spawn vllm serve microsoft/Phi-3.5-mini-instruct --port 8006


### Server #10
CUDA_VISIBLE_DEVICES=0,1,2,3 VLLM_WORKER_MULTIPROC_METHOD=spawn vllm serve Qwen/Qwen2.5-32B-Instruct --port 8000 -tp 4
CUDA_VISIBLE_DEVICES=4 VLLM_WORKER_MULTIPROC_METHOD=spawn vllm serve meta-llama/Llama-3.1-8B-Instruct --port 8001
CUDA_VISIBLE_DEVICES=5 VLLM_WORKER_MULTIPROC_METHOD=spawn vllm serve meta-llama/Llama-3.2-3B-Instruct --port 8002
CUDA_VISIBLE_DEVICES=6 VLLM_WORKER_MULTIPROC_METHOD=spawn vllm serve meta-llama/Llama-3.2-1B-Instruct --port 8003
CUDA_VISIBLE_DEVICES=7 VLLM_WORKER_MULTIPROC_METHOD=spawn vllm serve google/gemma-2-2b-it --port 8004
