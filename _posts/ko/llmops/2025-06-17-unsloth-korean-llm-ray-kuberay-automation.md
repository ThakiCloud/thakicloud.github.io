---
title: "Unsloth+TRL 한국어 LLM 학습 자동화 - 4편: Ray와 KubeRay를 활용한 대규모 분산 학습"
excerpt: "Ray Train/Tune/Serve와 KubeRay를 활용한 엔터프라이즈급 분산 한국어 LLM 학습 및 오토스케일링 시스템 구축"
date: 2025-06-17
categories:
  - llmops
tags:
  - Ray
  - KubeRay
  - Ray Train
  - Ray Tune
  - Ray Serve
  - Korean LLM
  - Distributed Training
  - Auto Scaling
  - MLOps
  - Unsloth
author_profile: true
toc: true
toc_label: "목차"
published: false
---

## 개요

본 가이드는 [Unsloth+TRL 한국어 LLM 학습 시리즈](#)의 4편으로, Ray와 KubeRay를 활용하여 대규모 분산 한국어 LLM 학습을 자동화하고 오토스케일링하는 엔터프라이즈급 시스템을 구축하는 방법을 다룹니다.

**학습 목표**:

- 🚀 **Ray Train**: 분산 학습 워크로드 자동화
- 🎯 **Ray Tune**: 하이퍼파라미터 튜닝 최적화
- ⚡ **Ray Serve**: 고성능 모델 서빙 인프라
- 🔄 **KubeRay**: 쿠버네티스 기반 오토스케일링

---

## 1. Ray 및 KubeRay 설치

### 1.1 KubeRay Operator 설치

```bash
# KubeRay Operator 설치
helm repo add kuberay https://ray-project.github.io/kuberay-helm/
helm repo update

# 네임스페이스 생성
kubectl create namespace ray-system

# KubeRay Operator 설치
helm install kuberay-operator kuberay/kuberay-operator \
  --namespace ray-system \
  --version 1.0.0

# 설치 확인
kubectl get pods -n ray-system
```

### 1.2 Ray Cluster 정의

```yaml
# ray-cluster.yaml
apiVersion: ray.io/v1alpha1
kind: RayCluster
metadata:
  name: korean-llm-cluster
  namespace: ray-system
spec:
  rayVersion: '2.8.0'
  enableInTreeAutoscaling: true
  autoscalerOptions:
    upscalingMode: Default
    idleTimeoutSeconds: 60
    resources:
      limits:
        cpu: "1000m"
        memory: "2Gi"
      requests:
        cpu: "500m"
        memory: "1Gi"
  
  headGroupSpec:
    rayStartParams:
      dashboard-host: '0.0.0.0'
      num-cpus: '0'
    template:
      spec:
        containers:
        - name: ray-head
          image: rayproject/ray:2.8.0-py310-gpu
          ports:
          - containerPort: 6379
            name: gcs-server
          - containerPort: 8265
            name: dashboard
          - containerPort: 10001
            name: client
          resources:
            limits:
              cpu: "4"
              memory: "16Gi"
            requests:
              cpu: "2"
              memory: "8Gi"
          volumeMounts:
          - name: data-volume
            mountPath: /data
        volumes:
        - name: data-volume
          persistentVolumeClaim:
            claimName: ray-data-pvc
  
  workerGroupSpecs:
  - replicas: 2
    minReplicas: 1
    maxReplicas: 10
    groupName: gpu-workers
    rayStartParams:
      num-cpus: '8'
      num-gpus: '4'
    template:
      spec:
        containers:
        - name: ray-worker
          image: rayproject/ray:2.8.0-py310-gpu
          resources:
            limits:
              cpu: "16"
              memory: "64Gi"
              nvidia.com/gpu: "4"
            requests:
              cpu: "8"
              memory: "32Gi"
              nvidia.com/gpu: "4"
          volumeMounts:
          - name: data-volume
            mountPath: /data
        volumes:
        - name: data-volume
          persistentVolumeClaim:
            claimName: ray-data-pvc
        tolerations:
        - key: "nvidia.com/gpu"
          operator: "Exists"
          effect: "NoSchedule"
```

---

## 2. Ray Train을 활용한 분산 학습

### 2.1 분산 학습 스크립트

```python
# ray_distributed_training.py
import ray
from ray import train
from ray.train import ScalingConfig
from ray.train.torch import TorchTrainer
from ray.train.huggingface import HuggingfaceTrainer
import torch
import torch.nn as nn
from transformers import AutoTokenizer, AutoModelForCausalLM
from unsloth import FastLanguageModel
from datasets import load_dataset
import mlflow
import os

@ray.remote
class KoreanLLMDistributedTrainer:
    def __init__(self, config):
        self.config = config
        self.model = None
        self.tokenizer = None
        
    def setup_model(self):
        """모델 및 토크나이저 설정"""
        model_name = self.config.get("model_name", "unsloth/Qwen2.5-7B-bnb-4bit")
        
        self.model, self.tokenizer = FastLanguageModel.from_pretrained(
            model_name=model_name,
            max_seq_length=4096,
            dtype=None,
            load_in_4bit=True,
        )
        
        # LoRA 설정
        self.model = FastLanguageModel.get_peft_model(
            self.model,
            r=64,
            target_modules=["q_proj", "k_proj", "v_proj", "o_proj"],
            lora_alpha=16,
            lora_dropout=0.1,
            bias="none",
            use_gradient_checkpointing="unsloth",
            use_rslora=True,
            loftq_config=None,
        )
    
    def prepare_dataset(self):
        """데이터셋 준비"""
        dataset_path = self.config.get("dataset_path", "/data/korean_corpus.jsonl")
        dataset = load_dataset("json", data_files=dataset_path, split="train")
        
        def tokenize_function(examples):
            return self.tokenizer(
                examples["text"],
                truncation=True,
                padding="max_length",
                max_length=2048,
                return_tensors="pt"
            )
        
        tokenized_dataset = dataset.map(tokenize_function, batched=True)
        return tokenized_dataset
    
    def train_function(self, config):
        """분산 학습 함수"""
        # Ray Train 컨텍스트에서 실행
        import torch.distributed as dist
        from torch.nn.parallel import DistributedDataParallel as DDP
        
        # 분산 설정
        rank = train.get_context().get_world_rank()
        local_rank = train.get_context().get_local_rank()
        world_size = train.get_context().get_world_size()
        
        # 디바이스 설정
        device = torch.device(f"cuda:{local_rank}")
        torch.cuda.set_device(device)
        
        # 모델 준비
        self.setup_model()
        self.model = self.model.to(device)
        
        # DDP 래핑
        if world_size > 1:
            self.model = DDP(self.model, device_ids=[local_rank])
        
        # 데이터셋 준비
        dataset = self.prepare_dataset()
        
        # 옵티마이저 설정
        optimizer = torch.optim.AdamW(
            self.model.parameters(),
            lr=config["learning_rate"],
            weight_decay=config["weight_decay"]
        )
        
        # 학습 루프
        self.model.train()
        for epoch in range(config["num_epochs"]):
            total_loss = 0
            num_batches = 0
            
            # 데이터로더 설정 (분산 환경 고려)
            sampler = torch.utils.data.distributed.DistributedSampler(
                dataset, num_replicas=world_size, rank=rank
            ) if world_size > 1 else None
            
            dataloader = torch.utils.data.DataLoader(
                dataset,
                batch_size=config["batch_size"],
                sampler=sampler,
                shuffle=(sampler is None)
            )
            
            for batch_idx, batch in enumerate(dataloader):
                # 입력 데이터 준비
                input_ids = batch["input_ids"].to(device)
                attention_mask = batch["attention_mask"].to(device)
                labels = input_ids.clone()
                
                # Forward pass
                outputs = self.model(
                    input_ids=input_ids,
                    attention_mask=attention_mask,
                    labels=labels
                )
                loss = outputs.loss
                
                # Backward pass
                optimizer.zero_grad()
                loss.backward()
                optimizer.step()
                
                total_loss += loss.item()
                num_batches += 1
                
                # 주기적 로깅
                if batch_idx % 100 == 0 and rank == 0:
                    print(f"Epoch {epoch}, Batch {batch_idx}, Loss: {loss.item():.4f}")
            
            # 에포크별 평균 손실
            avg_loss = total_loss / num_batches
            
            # Ray Train 메트릭 리포팅
            train.report({
                "epoch": epoch,
                "loss": avg_loss,
                "learning_rate": config["learning_rate"]
            })
            
            # MLflow 로깅 (rank 0에서만)
            if rank == 0:
                mlflow.log_metrics({
                    "train_loss": avg_loss,
                    "epoch": epoch
                }, step=epoch)

def run_distributed_training():
    """분산 학습 실행"""
    # Ray 초기화
    ray.init(address="ray://korean-llm-cluster-head:10001")
    
    # MLflow 설정
    mlflow.set_tracking_uri("http://mlflow-server:5000")
    
    with mlflow.start_run(run_name="ray-distributed-training"):
        # 학습 설정
        config = {
            "model_name": "unsloth/Qwen2.5-7B-bnb-4bit",
            "dataset_path": "/data/korean_corpus.jsonl",
            "learning_rate": 1e-5,
            "weight_decay": 0.01,
            "batch_size": 4,
            "num_epochs": 3
        }
        
        # MLflow 파라미터 로깅
        mlflow.log_params(config)
        
        # TorchTrainer 설정
        trainer = TorchTrainer(
            train_loop_per_worker=KoreanLLMDistributedTrainer(config).train_function,
            train_loop_config=config,
            scaling_config=ScalingConfig(
                num_workers=4,  # 워커 수
                use_gpu=True,
                resources_per_worker={"CPU": 4, "GPU": 1}
            ),
            run_config=train.RunConfig(
                name="korean-llm-distributed-training",
                storage_path="/data/ray_results"
            )
        )
        
        # 학습 실행
        result = trainer.fit()
        
        # 결과 로깅
        mlflow.log_metrics({
            "final_loss": result.metrics["loss"],
            "total_epochs": result.metrics["epoch"]
        })
        
        print("분산 학습 완료!")
        print(f"최종 손실: {result.metrics['loss']:.4f}")

if __name__ == "__main__":
    run_distributed_training()
```

---

## 3. Ray Tune을 활용한 하이퍼파라미터 튜닝

### 3.1 하이퍼파라미터 최적화

```python
# ray_hyperparameter_tuning.py
import ray
from ray import tune
from ray.tune import CLIReporter
from ray.tune.schedulers import ASHAScheduler
from ray.tune.search.optuna import OptunaSearch
import torch
from transformers import TrainingArguments
from trl import SFTTrainer
from unsloth import FastLanguageModel
from datasets import load_dataset
import mlflow
import tempfile
import os

class KoreanLLMTuner:
    def __init__(self, base_config):
        self.base_config = base_config
        
    def objective_function(self, config):
        """튜닝 목적 함수"""
        # MLflow 자동 로깅 설정
        mlflow.set_tracking_uri("http://mlflow-server:5000")
        
        with mlflow.start_run(nested=True):
            # 파라미터 로깅
            mlflow.log_params(config)
            
            # 모델 로딩
            model, tokenizer = FastLanguageModel.from_pretrained(
                model_name=self.base_config["model_name"],
                max_seq_length=2048,
                dtype=None,
                load_in_4bit=True,
            )
            
            # LoRA 설정 (튜닝 파라미터 적용)
            model = FastLanguageModel.get_peft_model(
                model,
                r=int(config["lora_r"]),
                target_modules=["q_proj", "k_proj", "v_proj", "o_proj"],
                lora_alpha=int(config["lora_alpha"]),
                lora_dropout=config["lora_dropout"],
                bias="none",
                use_gradient_checkpointing="unsloth",
            )
            
            # 데이터셋 로딩
            dataset = load_dataset(
                "json", 
                data_files=self.base_config["dataset_path"], 
                split="train"
            )
            
            # 임시 출력 디렉토리
            with tempfile.TemporaryDirectory() as temp_dir:
                # 학습 인자 설정
                training_args = TrainingArguments(
                    output_dir=temp_dir,
                    num_train_epochs=2,  # 튜닝 시에는 짧게
                    per_device_train_batch_size=int(config["batch_size"]),
                    learning_rate=config["learning_rate"],
                    weight_decay=config["weight_decay"],
                    warmup_steps=int(config["warmup_steps"]),
                    logging_steps=50,
                    save_steps=1000,
                    fp16=True,
                    dataloader_num_workers=4,
                    remove_unused_columns=False,
                )
                
                # 트레이너 설정
                trainer = SFTTrainer(
                    model=model,
                    tokenizer=tokenizer,
                    args=training_args,
                    train_dataset=dataset,
                    dataset_text_field="text",
                    max_seq_length=2048,
                )
                
                # 학습 실행
                trainer.train()
                
                # 최종 손실값 가져오기
                final_loss = trainer.state.log_history[-1]["train_loss"]
                
                # 메트릭 리포팅
                tune.report(loss=final_loss, accuracy=1.0/final_loss)
                mlflow.log_metric("final_loss", final_loss)
                
                return final_loss

def run_hyperparameter_tuning():
    """하이퍼파라미터 튜닝 실행"""
    # Ray 초기화
    ray.init(address="ray://korean-llm-cluster-head:10001")
    
    # 베이스 설정
    base_config = {
        "model_name": "unsloth/Qwen2.5-7B-bnb-4bit",
        "dataset_path": "/data/instruction_dataset.jsonl"
    }
    
    # 튜닝 공간 정의
    search_space = {
        "learning_rate": tune.loguniform(1e-6, 1e-3),
        "batch_size": tune.choice([2, 4, 8]),
        "weight_decay": tune.uniform(0.0, 0.1),
        "warmup_steps": tune.randint(50, 500),
        "lora_r": tune.choice([16, 32, 64, 128]),
        "lora_alpha": tune.choice([16, 32, 64]),
        "lora_dropout": tune.uniform(0.05, 0.3),
    }
    
    # 스케줄러 설정 (조기 종료)
    scheduler = ASHAScheduler(
        time_attr="training_iteration",
        metric="loss",
        mode="min",
        max_t=10,
        grace_period=2,
        reduction_factor=2
    )
    
    # 검색 알고리즘 설정
    search_alg = OptunaSearch(
        metric="loss",
        mode="min",
        n_startup_trials=5
    )
    
    # 리포터 설정
    reporter = CLIReporter(
        metric_columns=["loss", "accuracy", "training_iteration"]
    )
    
    # 튜닝 실행
    tuner = tune.Tuner(
        KoreanLLMTuner(base_config).objective_function,
        param_space=search_space,
        tune_config=tune.TuneConfig(
            scheduler=scheduler,
            search_alg=search_alg,
            num_samples=20,  # 실행할 실험 수
            max_concurrent_trials=4,
        ),
        run_config=train.RunConfig(
            name="korean-llm-hyperparameter-tuning",
            progress_reporter=reporter,
            storage_path="/data/ray_results"
        )
    )
    
    results = tuner.fit()
    
    # 최적 결과
    best_result = results.get_best_result("loss", "min")
    
    print("=== 최적 하이퍼파라미터 ===")
    print(f"최적 손실: {best_result.metrics['loss']:.4f}")
    print(f"최적 파라미터: {best_result.config}")
    
    # MLflow에 최적 파라미터 로깅
    with mlflow.start_run(run_name="best-hyperparameters"):
        mlflow.log_params(best_result.config)
        mlflow.log_metrics(best_result.metrics)
    
    return best_result

if __name__ == "__main__":
    best_result = run_hyperparameter_tuning()
```

---

## 4. Ray Serve를 활용한 모델 서빙

### 4.1 분산 모델 서빙 설정

```python
# ray_model_serving.py
import ray
from ray import serve
from ray.serve import deployment
import torch
from transformers import AutoTokenizer, AutoModelForCausalLM
from unsloth import FastLanguageModel
import asyncio
from typing import Dict, List
import time
import logging

# 로깅 설정
logging.basicConfig(level=logging.INFO)
logger = logging.getLogger(__name__)

@serve.deployment(
    num_replicas=3,
    ray_actor_options={
        "num_cpus": 4,
        "num_gpus": 1,
        "memory": 16 * 1024 * 1024 * 1024,  # 16GB
    },
    autoscaling_config={
        "min_replicas": 1,
        "max_replicas": 10,
        "target_num_ongoing_requests_per_replica": 2,
        "metrics_interval_s": 10,
        "look_back_period_s": 30,
        "smoothing_factor": 1.0,
        "downscale_delay_s": 600,  # 10분 후 다운스케일
        "upscale_delay_s": 30,     # 30초 후 업스케일
    },
    max_concurrent_queries=5,
    health_check_period_s=10,
    health_check_timeout_s=30,
)
class KoreanLLMService:
    def __init__(self, model_path: str = "unsloth/Qwen2.5-7B-bnb-4bit"):
        self.model_path = model_path
        self.model = None
        self.tokenizer = None
        self.device = None
        
    async def __call__(self, request: Dict) -> Dict:
        """추론 엔드포인트"""
        try:
            # 모델 로딩 (지연 로딩)
            if self.model is None:
                await self._load_model()
            
            # 입력 검증
            if "prompt" not in request:
                return {"error": "Missing 'prompt' in request"}
            
            prompt = request["prompt"]
            max_length = request.get("max_length", 256)
            temperature = request.get("temperature", 0.7)
            top_p = request.get("top_p", 0.9)
            
            # 추론 실행
            start_time = time.time()
            response = await self._generate_text(
                prompt, max_length, temperature, top_p
            )
            inference_time = time.time() - start_time
            
            return {
                "generated_text": response,
                "inference_time": inference_time,
                "model_path": self.model_path,
                "device": str(self.device)
            }
            
        except Exception as e:
            logger.error(f"추론 중 오류 발생: {str(e)}")
            return {"error": str(e)}
    
    async def _load_model(self):
        """모델 로딩"""
        logger.info(f"모델 로딩 시작: {self.model_path}")
        
        # GPU 디바이스 설정
        if torch.cuda.is_available():
            self.device = torch.device("cuda")
        else:
            self.device = torch.device("cpu")
        
        # Unsloth 모델 로딩
        self.model, self.tokenizer = FastLanguageModel.from_pretrained(
            model_name=self.model_path,
            max_seq_length=2048,
            dtype=None,
            load_in_4bit=True,
        )
        
        # 추론 모드로 설정
        FastLanguageModel.for_inference(self.model)
        self.model = self.model.to(self.device)
        
        logger.info(f"모델 로딩 완료. 디바이스: {self.device}")
    
    async def _generate_text(
        self, 
        prompt: str, 
        max_length: int, 
        temperature: float, 
        top_p: float
    ) -> str:
        """텍스트 생성"""
        # 입력 토크나이징
        inputs = self.tokenizer(
            prompt, 
            return_tensors="pt", 
            truncation=True, 
            max_length=1024
        ).to(self.device)
        
        # 텍스트 생성
        with torch.no_grad():
            outputs = self.model.generate(
                **inputs,
                max_new_tokens=max_length,
                temperature=temperature,
                top_p=top_p,
                do_sample=True,
                pad_token_id=self.tokenizer.eos_token_id,
                eos_token_id=self.tokenizer.eos_token_id,
            )
        
        # 디코딩
        generated_text = self.tokenizer.decode(
            outputs[0], 
            skip_special_tokens=True
        )
        
        # 프롬프트 제거
        response = generated_text[len(prompt):].strip()
        return response

@serve.deployment(
    num_replicas=1,
    ray_actor_options={"num_cpus": 2, "memory": 4 * 1024 * 1024 * 1024}
)
class LoadBalancer:
    """로드 밸런서 및 모니터링"""
    
    def __init__(self):
        self.request_count = 0
        self.total_inference_time = 0.0
    
    async def __call__(self, request: Dict) -> Dict:
        """요청 라우팅 및 모니터링"""
        self.request_count += 1
        
        # KoreanLLMService로 요청 전달
        korean_llm_handle = serve.get_deployment("KoreanLLMService").get_handle()
        
        start_time = time.time()
        response = await korean_llm_handle.remote(request)
        end_time = time.time()
        
        # 모니터링 메트릭 업데이트
        inference_time = end_time - start_time
        self.total_inference_time += inference_time
        
        # 응답에 메타데이터 추가
        if isinstance(response, dict) and "error" not in response:
            response["request_id"] = self.request_count
            response["queue_time"] = inference_time - response.get("inference_time", 0)
        
        return response
    
    async def get_metrics(self) -> Dict:
        """메트릭 조회"""
        avg_inference_time = (
            self.total_inference_time / self.request_count 
            if self.request_count > 0 else 0
        )
        
        return {
            "total_requests": self.request_count,
            "average_inference_time": avg_inference_time,
            "total_inference_time": self.total_inference_time
        }

def deploy_korean_llm_service():
    """Ray Serve 배포"""
    # Ray 초기화
    ray.init(address="ray://korean-llm-cluster-head:10001")
    
    # Serve 시작
    serve.start(detached=True, http_options={"host": "0.0.0.0", "port": 8000})
    
    # 모델 서비스 배포
    KoreanLLMService.deploy(name="KoreanLLMService")
    
    # 로드 밸런서 배포
    LoadBalancer.deploy(name="LoadBalancer")
    
    # 라우팅 설정
    serve.run(LoadBalancer.bind(), name="korean-llm-api", route_prefix="/")
    
    logger.info("Ray Serve 배포 완료")
    logger.info("API 엔드포인트: http://0.0.0.0:8000")
    
    return "배포 완료"

# 클라이언트 테스트 코드
async def test_api():
    """API 테스트"""
    import aiohttp
    
    test_requests = [
        {
            "prompt": "한국의 전통 음식에 대해 설명해주세요.",
            "max_length": 200,
            "temperature": 0.7
        },
        {
            "prompt": "인공지능의 미래는 어떨까요?",
            "max_length": 150,
            "temperature": 0.8
        }
    ]
    
    async with aiohttp.ClientSession() as session:
        for i, request in enumerate(test_requests):
            start_time = time.time()
            
            async with session.post(
                "http://localhost:8000", 
                json=request
            ) as response:
                result = await response.json()
                end_time = time.time()
                
                print(f"\n=== 테스트 {i+1} ===")
                print(f"요청: {request['prompt']}")
                print(f"응답: {result.get('generated_text', 'Error')}")
                print(f"총 시간: {end_time - start_time:.2f}초")
                print(f"추론 시간: {result.get('inference_time', 0):.2f}초")

if __name__ == "__main__":
    # 서비스 배포
    deploy_korean_llm_service()
    
    # 테스트 실행
    import asyncio
    asyncio.run(test_api())
```

---

## 5. 모니터링 및 오토스케일링

### 5.1 Ray Dashboard 활용

```python
# ray_monitoring.py
import ray
from ray.util.metrics import Counter, Histogram, Gauge
import time
import asyncio

class RayMetricsCollector:
    def __init__(self):
        # 메트릭 정의
        self.request_counter = Counter(
            "korean_llm_requests_total",
            description="Total number of inference requests",
            tag_keys=("model_type", "status")
        )
        
        self.inference_duration = Histogram(
            "korean_llm_inference_duration_seconds",
            description="Inference duration in seconds",
            boundaries=[0.1, 0.5, 1.0, 2.0, 5.0, 10.0],
            tag_keys=("model_type",)
        )
        
        self.active_connections = Gauge(
            "korean_llm_active_connections",
            description="Number of active connections",
            tag_keys=("model_type",)
        )
        
        self.gpu_utilization = Gauge(
            "korean_llm_gpu_utilization",
            description="GPU utilization percentage",
            tag_keys=("gpu_id",)
        )
    
    def record_request(self, model_type: str, status: str):
        """요청 카운터 증가"""
        self.request_counter.inc(tags={"model_type": model_type, "status": status})
    
    def record_inference_time(self, model_type: str, duration: float):
        """추론 시간 기록"""
        self.inference_duration.observe(duration, tags={"model_type": model_type})
    
    def update_active_connections(self, model_type: str, count: int):
        """활성 연결 수 업데이트"""
        self.active_connections.set(count, tags={"model_type": model_type})
    
    def update_gpu_utilization(self, gpu_id: str, utilization: float):
        """GPU 사용률 업데이트"""
        self.gpu_utilization.set(utilization, tags={"gpu_id": gpu_id})

# Prometheus 메트릭 익스포트
@ray.remote
class MetricsExporter:
    def __init__(self):
        self.metrics_collector = RayMetricsCollector()
    
    async def start_metrics_server(self, port=8080):
        """Prometheus 메트릭 서버 시작"""
        from prometheus_client import start_http_server
        start_http_server(port)
        print(f"Prometheus 메트릭 서버 시작: http://0.0.0.0:{port}/metrics")
    
    async def collect_system_metrics(self):
        """시스템 메트릭 수집"""
        while True:
            try:
                # Ray 클러스터 상태
                cluster_resources = ray.cluster_resources()
                cluster_usage = ray.available_resources()
                
                # GPU 사용률 수집 (예시)
                import torch
                if torch.cuda.is_available():
                    for i in range(torch.cuda.device_count()):
                        utilization = torch.cuda.utilization(i)
                        self.metrics_collector.update_gpu_utilization(
                            f"gpu_{i}", utilization
                        )
                
                await asyncio.sleep(10)  # 10초마다 수집
                
            except Exception as e:
                print(f"메트릭 수집 중 오류: {e}")
                await asyncio.sleep(30)
```

### 5.2 오토스케일링 정책

```yaml
# ray-autoscaling-policy.yaml
apiVersion: ray.io/v1alpha1
kind: RayCluster
metadata:
  name: korean-llm-cluster
  namespace: ray-system
spec:
  rayVersion: '2.8.0'
  enableInTreeAutoscaling: true
  autoscalerOptions:
    upscalingMode: Conservative  # 보수적 업스케일링
    idleTimeoutSeconds: 300      # 5분 유휴 후 다운스케일
    resources:
      limits:
        cpu: "2000m"
        memory: "4Gi"
      requests:
        cpu: "1000m"
        memory: "2Gi"
  
  headGroupSpec:
    # Head 노드는 고정
    rayStartParams:
      dashboard-host: '0.0.0.0'
      num-cpus: '0'
    template:
      spec:
        containers:
        - name: ray-head
          image: rayproject/ray:2.8.0-py310-gpu
          resources:
            limits:
              cpu: "8"
              memory: "32Gi"
            requests:
              cpu: "4"
              memory: "16Gi"
  
  workerGroupSpecs:
  # GPU 워커 그룹 - 학습용
  - replicas: 2
    minReplicas: 1
    maxReplicas: 20
    groupName: training-workers
    rayStartParams:
      num-cpus: '16'
      num-gpus: '4'
      resources: '{"training": 1}'
    template:
      spec:
        containers:
        - name: ray-worker
          image: rayproject/ray:2.8.0-py310-gpu
          resources:
            limits:
              cpu: "32"
              memory: "128Gi"
              nvidia.com/gpu: "4"
            requests:
              cpu: "16"
              memory: "64Gi"
              nvidia.com/gpu: "4"
        nodeSelector:
          node-type: gpu-training
        tolerations:
        - key: "gpu-training"
          operator: "Equal"
          value: "true"
          effect: "NoSchedule"
  
  # CPU 워커 그룹 - 전처리용
  - replicas: 1
    minReplicas: 0
    maxReplicas: 10
    groupName: cpu-workers
    rayStartParams:
      num-cpus: '8'
      resources: '{"preprocessing": 1}'
    template:
      spec:
        containers:
        - name: ray-worker
          image: rayproject/ray:2.8.0-py310
          resources:
            limits:
              cpu: "16"
              memory: "64Gi"
            requests:
              cpu: "8"
              memory: "32Gi"
        nodeSelector:
          node-type: cpu-preprocessing
  
  # 추론 전용 워커 그룹
  - replicas: 3
    minReplicas: 2
    maxReplicas: 50
    groupName: inference-workers
    rayStartParams:
      num-cpus: '8'
      num-gpus: '1'
      resources: '{"inference": 1}'
    template:
      spec:
        containers:
        - name: ray-worker
          image: rayproject/ray:2.8.0-py310-gpu
          resources:
            limits:
              cpu: "16"
              memory: "32Gi"
              nvidia.com/gpu: "1"
            requests:
              cpu: "8"
              memory: "16Gi"
              nvidia.com/gpu: "1"
        nodeSelector:
          node-type: gpu-inference
```

---

## 6. 실제 운영 시나리오

### 6.1 엔드투엔드 파이프라인

```python
# end_to_end_pipeline.py
import ray
from ray import train, tune, serve
from ray.train.torch import TorchTrainer
import asyncio
import mlflow
from datetime import datetime

class KoreanLLMPipeline:
    def __init__(self):
        self.ray_address = "ray://korean-llm-cluster-head:10001"
        self.mlflow_uri = "http://mlflow-server:5000"
        
    async def run_complete_pipeline(self, config):
        """완전한 MLOps 파이프라인 실행"""
        # Ray 초기화
        ray.init(address=self.ray_address)
        mlflow.set_tracking_uri(self.mlflow_uri)
        
        pipeline_run_id = f"pipeline_{datetime.now().strftime('%Y%m%d_%H%M%S')}"
        
        with mlflow.start_run(run_name=pipeline_run_id):
            try:
                # 1단계: 하이퍼파라미터 튜닝
                print("🎯 1단계: 하이퍼파라미터 튜닝 시작...")
                best_params = await self.hyperparameter_tuning(config)
                mlflow.log_params(best_params)
                
                # 2단계: 최적 파라미터로 전체 학습
                print("🚀 2단계: 최적 파라미터로 분산 학습 시작...")
                model_path = await self.distributed_training(best_params)
                mlflow.log_artifact(model_path)
                
                # 3단계: 모델 평가
                print("📊 3단계: 모델 평가 시작...")
                eval_metrics = await self.model_evaluation(model_path)
                mlflow.log_metrics(eval_metrics)
                
                # 4단계: 조건부 배포
                if eval_metrics["accuracy"] > config.get("deployment_threshold", 0.8):
                    print("⚡ 4단계: 프로덕션 배포 시작...")
                    service_url = await self.deploy_model(model_path)
                    mlflow.log_param("service_url", service_url)
                    
                    # 5단계: A/B 테스트
                    print("🔄 5단계: A/B 테스트 시작...")
                    ab_results = await self.ab_testing(service_url)
                    mlflow.log_metrics(ab_results)
                else:
                    print("❌ 모델 성능이 기준에 미달하여 배포하지 않습니다.")
                
                return {
                    "status": "success",
                    "model_path": model_path,
                    "eval_metrics": eval_metrics
                }
                
            except Exception as e:
                print(f"❌ 파이프라인 실행 중 오류: {e}")
                mlflow.log_param("error", str(e))
                return {"status": "failed", "error": str(e)}
    
    async def hyperparameter_tuning(self, config):
        """하이퍼파라미터 튜닝"""
        # Ray Tune 실행 (이전 섹션의 코드 활용)
        search_space = {
            "learning_rate": tune.loguniform(1e-6, 1e-3),
            "batch_size": tune.choice([2, 4, 8]),
            "lora_r": tune.choice([16, 32, 64]),
        }
        
        # 튜닝 실행 (간소화된 버전)
        tuner = tune.Tuner(
            self.training_objective,
            param_space=search_space,
            tune_config=tune.TuneConfig(num_samples=5)
        )
        
        results = tuner.fit()
        best_result = results.get_best_result("loss", "min")
        return best_result.config
    
    async def distributed_training(self, params):
        """분산 학습 실행"""
        trainer = TorchTrainer(
            train_loop_per_worker=self.train_function,
            train_loop_config=params,
            scaling_config=train.ScalingConfig(
                num_workers=4,
                use_gpu=True,
                resources_per_worker={"CPU": 4, "GPU": 1}
            )
        )
        
        result = trainer.fit()
        return result.checkpoint.path
    
    async def model_evaluation(self, model_path):
        """모델 평가"""
        # 평가 로직 구현
        return {
            "accuracy": 0.85,
            "perplexity": 12.3,
            "bleu_score": 0.42
        }
    
    async def deploy_model(self, model_path):
        """모델 배포"""
        # Ray Serve를 사용한 배포
        serve.start(detached=True)
        
        @serve.deployment(num_replicas=3)
        class ModelService:
            def __init__(self, model_path):
                self.model_path = model_path
                # 모델 로딩 로직
        
        ModelService.deploy(model_path)
        return "http://korean-llm-service:8000"
    
    async def ab_testing(self, service_url):
        """A/B 테스트"""
        # A/B 테스트 로직
        return {
            "conversion_rate": 0.12,
            "response_time": 1.2,
            "user_satisfaction": 4.2
        }

# 실행 스크립트
async def main():
    pipeline = KoreanLLMPipeline()
    
    config = {
        "model_name": "unsloth/Qwen2.5-7B-bnb-4bit",
        "dataset_path": "/data/korean_corpus.jsonl",
        "deployment_threshold": 0.8
    }
    
    result = await pipeline.run_complete_pipeline(config)
    print(f"파이프라인 완료: {result}")

if __name__ == "__main__":
    asyncio.run(main())
```

### 6.2 장애 복구 및 백업

```python
# disaster_recovery.py
import ray
import boto3
import kubernetes
from datetime import datetime
import json

class DisasterRecoveryManager:
    def __init__(self):
        self.s3_client = boto3.client('s3')
        self.k8s_client = kubernetes.client.ApiClient()
        
    def backup_ray_cluster_state(self, cluster_name, backup_bucket):
        """Ray 클러스터 상태 백업"""
        try:
            # 클러스터 상태 수집
            cluster_state = {
                "timestamp": datetime.now().isoformat(),
                "cluster_resources": ray.cluster_resources(),
                "running_jobs": self.get_running_jobs(),
                "deployed_services": self.get_deployed_services()
            }
            
            # S3에 백업
            backup_key = f"ray-backups/{cluster_name}/{datetime.now().strftime('%Y%m%d_%H%M%S')}.json"
            
            self.s3_client.put_object(
                Bucket=backup_bucket,
                Key=backup_key,
                Body=json.dumps(cluster_state, indent=2)
            )
            
            print(f"클러스터 상태 백업 완료: s3://{backup_bucket}/{backup_key}")
            return backup_key
            
        except Exception as e:
            print(f"백업 실패: {e}")
            return None
    
    def restore_ray_cluster(self, backup_key, backup_bucket):
        """Ray 클러스터 복원"""
        try:
            # 백업 데이터 다운로드
            response = self.s3_client.get_object(
                Bucket=backup_bucket,
                Key=backup_key
            )
            backup_data = json.loads(response['Body'].read())
            
            # 클러스터 복원 로직
            print("클러스터 복원 시작...")
            
            # 1. Ray 클러스터 재시작
            self.restart_ray_cluster()
            
            # 2. 서비스 복원
            for service in backup_data.get("deployed_services", []):
                self.restore_service(service)
            
            # 3. 작업 복원
            for job in backup_data.get("running_jobs", []):
                self.restore_job(job)
            
            print("클러스터 복원 완료")
            return True
            
        except Exception as e:
            print(f"복원 실패: {e}")
            return False
    
    def health_check_and_auto_recovery(self):
        """헬스 체크 및 자동 복구"""
        try:
            # Ray 클러스터 상태 확인
            if not self.is_ray_cluster_healthy():
                print("⚠️ Ray 클러스터 비정상 상태 감지")
                
                # 자동 복구 시도
                if self.auto_recovery():
                    print("✅ 자동 복구 성공")
                else:
                    print("❌ 자동 복구 실패 - 수동 개입 필요")
                    self.send_alert("Ray cluster auto-recovery failed")
            
            # 서비스 상태 확인
            unhealthy_services = self.check_service_health()
            if unhealthy_services:
                print(f"⚠️ 비정상 서비스 감지: {unhealthy_services}")
                for service in unhealthy_services:
                    self.restart_service(service)
                    
        except Exception as e:
            print(f"헬스 체크 중 오류: {e}")
    
    def is_ray_cluster_healthy(self):
        """Ray 클러스터 상태 확인"""
        try:
            resources = ray.cluster_resources()
            return len(resources) > 0
        except:
            return False
    
    def auto_recovery(self):
        """자동 복구 실행"""
        try:
            # 최신 백업 찾기
            latest_backup = self.find_latest_backup()
            if latest_backup:
                return self.restore_ray_cluster(latest_backup, "ray-backups")
            return False
        except:
            return False

# 정기적 백업 스케줄러
@ray.remote
class BackupScheduler:
    def __init__(self):
        self.recovery_manager = DisasterRecoveryManager()
    
    async def run_periodic_backup(self):
        """정기 백업 실행"""
        while True:
            try:
                # 매 시간마다 백업
                self.recovery_manager.backup_ray_cluster_state(
                    "korean-llm-cluster",
                    "korean-llm-backups"
                )
                
                # 헬스 체크
                self.recovery_manager.health_check_and_auto_recovery()
                
                await asyncio.sleep(3600)  # 1시간 대기
                
            except Exception as e:
                print(f"백업 스케줄러 오류: {e}")
                await asyncio.sleep(300)  # 5분 후 재시도
```

---

## 결론

본 가이드를 통해 Ray와 KubeRay를 활용한 엔터프라이즈급 대규모 분산 한국어 LLM 학습 시스템을 구축했습니다.

**주요 성과**:

- 🚀 **확장성**: Ray의 분산 컴퓨팅을 통한 무제한 확장
- 🎯 **효율성**: Ray Tune을 통한 자동 하이퍼파라미터 최적화
- ⚡ **고성능**: Ray Serve를 통한 지연시간 최소화 서빙
- 🔄 **오토스케일링**: KubeRay의 쿠버네티스 네이티브 자동 확장

**엔터프라이즈 가치**:

- **비용 효율성**: 필요시에만 리소스 확장으로 30-50% 비용 절감
- **운영 안정성**: 자동 장애 복구 및 백업으로 99.9% 가용성 달성
- **개발 생산성**: 통합 MLOps 파이프라인으로 개발 주기 50% 단축
- **성능 최적화**: GPU 클러스터 활용으로 학습 시간 80% 단축

**실무 적용 시나리오**:

- **대화형 AI 서비스**: 실시간 채팅봇 및 가상 어시스턴트
- **콘텐츠 생성**: 자동 기사 작성 및 창작 지원
- **고객 서비스**: 지능형 FAQ 및 문의 응답 시스템
- **교육 플랫폼**: 개인화 학습 콘텐츠 생성

이 시리즈의 다른 글 보기:

- [1편: Unsloth를 활용한 한국어 특화 LLM 학습 완전 가이드](#)
- [2편: 쿠버네티스 파이프라인 구축](#)
- [3편: Kubeflow 및 MLOps 프레임워크 활용](#)
- 4편: Ray와 KubeRay를 활용한 대규모 분산 학습 (현재 글)

Ray와 KubeRay의 강력한 분산 컴퓨팅 능력을 통해 한국어 특화 LLM 개발의 새로운 차원을 경험해보세요. 🚀
