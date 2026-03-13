use anyhow::Result;
use serde::{Deserialize, Serialize};
use std::collections::HashMap;
use std::sync::Arc;
use std::time::{Duration, Instant};
use tokio::sync::{RwLock, Semaphore, mpsc};
use tokio::time::sleep;
use tracing::{error, info};
//use std::sync::atomic::{AtomicUsize, AtomicU64, Ordering};

/// 2025年异步机器学习模式演示
/// 展示最新的异步机器学习编程模式和最佳实践

/// 1. 异步模型训练管理器
#[derive(Debug, Clone, Serialize, Deserialize)]
pub struct TrainingConfig {
    pub model_name: String,
    pub learning_rate: f64,
    pub batch_size: usize,
    pub epochs: usize,
    pub validation_split: f64,
    pub early_stopping_patience: usize,
}

impl Default for TrainingConfig {
    fn default() -> Self {
        Self {
            model_name: "default_model".to_string(),
            learning_rate: 0.001,
            batch_size: 32,
            epochs: 100,
            validation_split: 0.2,
            early_stopping_patience: 10,
        }
    }
}

#[derive(Debug, Clone)]
pub struct AsyncModelTrainer {
    config: TrainingConfig,
    training_data: Arc<RwLock<Vec<TrainingSample>>>,
    model_state: Arc<RwLock<ModelState>>,
    training_stats: Arc<RwLock<TrainingStats>>,
    progress_sender: mpsc::UnboundedSender<TrainingProgress>,
}

#[derive(Debug, Clone, Serialize, Deserialize)]
pub struct TrainingSample {
    pub id: String,
    pub features: Vec<f64>,
    pub label: f64,
    pub weight: Option<f64>,
}

#[derive(Debug, Clone, Serialize, Deserialize)]
pub struct ModelState {
    pub weights: Vec<f64>,
    pub bias: f64,
    pub version: u64,
    pub accuracy: f64,
    pub loss: f64,
    pub last_updated: u64,
}

#[derive(Debug, Clone, Default)]
pub struct TrainingStats {
    pub total_samples: usize,
    pub processed_samples: usize,
    pub training_epochs: usize,
    pub validation_epochs: usize,
    pub best_accuracy: f64,
    pub best_loss: f64,
    pub training_time: Duration,
}

#[derive(Debug, Clone)]
pub struct TrainingProgress {
    pub epoch: usize,
    pub accuracy: f64,
    pub loss: f64,
    pub validation_accuracy: f64,
    pub validation_loss: f64,
    pub timestamp: u64,
}

impl AsyncModelTrainer {
    pub fn new(config: TrainingConfig) -> (Self, mpsc::UnboundedReceiver<TrainingProgress>) {
        let (progress_sender, progress_receiver) = mpsc::unbounded_channel();

        let trainer = Self {
            config,
            training_data: Arc::new(RwLock::new(Vec::new())),
            model_state: Arc::new(RwLock::new(ModelState {
                weights: vec![0.0; 10], // 假设10个特征
                bias: 0.0,
                version: 0,
                accuracy: 0.0,
                loss: f64::INFINITY,
                last_updated: std::time::SystemTime::now()
                    .duration_since(std::time::UNIX_EPOCH)
                    .unwrap()
                    .as_secs(),
            })),
            training_stats: Arc::new(RwLock::new(TrainingStats::default())),
            progress_sender,
        };

        (trainer, progress_receiver)
    }

    pub async fn add_training_data(&self, samples: Vec<TrainingSample>) -> Result<()> {
        let mut data = self.training_data.write().await;
        data.extend(samples);

        let mut stats = self.training_stats.write().await;
        stats.total_samples = data.len();

        info!("添加训练数据，总样本数: {}", stats.total_samples);
        Ok(())
    }

    pub async fn start_training(&self) -> Result<()> {
        info!("开始模型训练: {}", self.config.model_name);
        let start_time = Instant::now();

        let data = self.training_data.read().await;
        let total_samples = data.len();

        if total_samples == 0 {
            return Err(anyhow::anyhow!("没有训练数据"));
        }

        let validation_size = (total_samples as f64 * self.config.validation_split) as usize;
        let training_size = total_samples - validation_size;

        info!(
            "训练集大小: {}, 验证集大小: {}",
            training_size, validation_size
        );

        let mut best_accuracy = 0.0;
        let mut patience_counter = 0;

        for epoch in 0..self.config.epochs {
            // 模拟训练一个epoch
            let (train_acc, train_loss) = self.train_epoch(epoch, &data[..training_size]).await?;

            // 模拟验证
            let (val_acc, val_loss) = self.validate_epoch(&data[training_size..]).await?;

            // 更新模型状态
            let mut model_state = self.model_state.write().await;
            model_state.accuracy = train_acc;
            model_state.loss = train_loss;
            model_state.version += 1;
            model_state.last_updated = std::time::SystemTime::now()
                .duration_since(std::time::UNIX_EPOCH)
                .unwrap()
                .as_secs();

            // 发送进度更新
            let progress = TrainingProgress {
                epoch,
                accuracy: train_acc,
                loss: train_loss,
                validation_accuracy: val_acc,
                validation_loss: val_loss,
                timestamp: std::time::SystemTime::now()
                    .duration_since(std::time::UNIX_EPOCH)
                    .unwrap()
                    .as_secs(),
            };

            let _ = self.progress_sender.send(progress);

            // 早停检查
            if val_acc > best_accuracy {
                best_accuracy = val_acc;
                patience_counter = 0;
            } else {
                patience_counter += 1;
                if patience_counter >= self.config.early_stopping_patience {
                    info!("早停触发，在第 {} epoch 停止训练", epoch);
                    break;
                }
            }

            info!(
                "Epoch {}: 训练准确率: {:.4}, 验证准确率: {:.4}",
                epoch, train_acc, val_acc
            );
        }

        let training_time = start_time.elapsed();
        let mut stats = self.training_stats.write().await;
        stats.training_epochs = self.config.epochs;
        stats.best_accuracy = best_accuracy;
        stats.training_time = training_time;

        info!(
            "训练完成，耗时: {:?}, 最佳准确率: {:.4}",
            training_time, best_accuracy
        );
        Ok(())
    }

    #[allow(unused_variables)]
    async fn train_epoch(&self, epoch: usize, data: &[TrainingSample]) -> Result<(f64, f64)> {
        // 模拟训练过程
        sleep(Duration::from_millis(100)).await;

        // 模拟梯度下降更新
        let mut model_state = self.model_state.write().await;
        for (i, weight) in model_state.weights.iter_mut().enumerate() {
            *weight += self.config.learning_rate * (0.1 - *weight);
        }
        model_state.bias += self.config.learning_rate * (0.05 - model_state.bias);

        // 模拟计算准确率和损失
        let mut correct = 0;
        let mut total_loss = 0.0;

        for sample in data.iter().take(self.config.batch_size) {
            let prediction = self.predict(&sample.features, &model_state).await;
            let error = (prediction - sample.label).abs();
            total_loss += error;

            if error < 0.5 {
                correct += 1;
            }
        }

        let accuracy = correct as f64 / data.len().min(self.config.batch_size) as f64;
        let loss = total_loss / data.len().min(self.config.batch_size) as f64;

        Ok((accuracy, loss))
    }

    #[allow(unused_variables)]
    async fn validate_epoch(&self, data: &[TrainingSample]) -> Result<(f64, f64)> {
        // 模拟验证过程
        sleep(Duration::from_millis(50)).await;

        let model_state = self.model_state.read().await;
        let mut correct = 0;
        let mut total_loss = 0.0;

        for sample in data.iter().take(self.config.batch_size / 2) {
            let prediction = self.predict(&sample.features, &model_state).await;
            let error = (prediction - sample.label).abs();
            total_loss += error;

            if error < 0.5 {
                correct += 1;
            }
        }

        let accuracy = correct as f64 / data.len().min(self.config.batch_size / 2) as f64;
        let loss = total_loss / data.len().min(self.config.batch_size / 2) as f64;

        Ok((accuracy, loss))
    }

    async fn predict(&self, features: &[f64], model_state: &ModelState) -> f64 {
        let mut result = model_state.bias;
        for (feature, weight) in features.iter().zip(model_state.weights.iter()) {
            result += feature * weight;
        }
        // 简化的激活函数
        result.tanh()
    }

    pub async fn get_model_state(&self) -> ModelState {
        self.model_state.read().await.clone()
    }

    pub async fn get_training_stats(&self) -> TrainingStats {
        self.training_stats.read().await.clone()
    }
}

/// 2. 异步模型推理服务
#[allow(dead_code)]
#[derive(Debug, Clone)]
pub struct AsyncInferenceService {
    models: Arc<RwLock<HashMap<String, ModelState>>>,
    inference_queue: Arc<RwLock<Vec<InferenceRequest>>>,
    inference_stats: Arc<RwLock<InferenceStats>>,
    max_concurrent_requests: usize,
    semaphore: Arc<Semaphore>,
}

#[allow(dead_code)]
#[derive(Debug, Clone, Serialize, Deserialize)]
pub struct InferenceRequest {
    pub id: String,
    pub model_name: String,
    pub features: Vec<f64>,
    pub priority: InferencePriority,
    pub created_at: u64,
    pub timeout: Duration,
}

#[derive(Debug, Clone, PartialEq, Serialize, Deserialize)]
pub enum InferencePriority {
    Low,
    Normal,
    High,
    Critical,
}

#[derive(Debug, Clone, Serialize, Deserialize)]
pub struct InferenceResult {
    pub request_id: String,
    pub prediction: f64,
    pub confidence: f64,
    pub processing_time: Duration,
    pub model_version: u64,
}

#[derive(Debug, Clone, Default)]
pub struct InferenceStats {
    pub total_requests: usize,
    pub successful_requests: usize,
    pub failed_requests: usize,
    pub average_processing_time: Duration,
    pub queue_size: usize,
}

impl AsyncInferenceService {
    pub fn new(max_concurrent_requests: usize) -> Self {
        Self {
            models: Arc::new(RwLock::new(HashMap::new())),
            inference_queue: Arc::new(RwLock::new(Vec::new())),
            inference_stats: Arc::new(RwLock::new(InferenceStats::default())),
            max_concurrent_requests,
            semaphore: Arc::new(Semaphore::new(max_concurrent_requests)),
        }
    }

    pub async fn register_model(&self, model_name: String, model_state: ModelState) -> Result<()> {
        let mut models = self.models.write().await;
        models.insert(model_name.clone(), model_state);
        info!("注册模型: {}", model_name);
        Ok(())
    }

    pub async fn submit_inference_request(&self, request: InferenceRequest) -> Result<String> {
        let mut queue = self.inference_queue.write().await;
        queue.push(request.clone());

        let mut stats = self.inference_stats.write().await;
        stats.total_requests += 1;
        stats.queue_size = queue.len();

        info!(
            "提交推理请求: {} (模型: {})",
            request.id, request.model_name
        );

        // 启动异步处理
        let service_clone = self.clone();
        let request_id = request.id.clone();
        tokio::spawn(async move {
            if let Err(e) = service_clone.process_inference_request(request).await {
                error!("推理请求处理失败: {}", e);
            }
        });

        Ok(request_id)
    }

    async fn process_inference_request(
        &self,
        request: InferenceRequest,
    ) -> Result<InferenceResult> {
        let _permit = self.semaphore.acquire().await.unwrap();
        let start_time = Instant::now();

        // 获取模型
        let models = self.models.read().await;
        let model_state = models
            .get(&request.model_name)
            .ok_or_else(|| anyhow::anyhow!("模型 {} 未找到", request.model_name))?;

        // 执行推理
        let prediction = self.run_inference(&request.features, model_state).await;

        // 计算置信度（简化实现）
        let confidence = 1.0 - (prediction.abs() * 0.1);

        let processing_time = start_time.elapsed();
        let result = InferenceResult {
            request_id: request.id.clone(),
            prediction,
            confidence,
            processing_time,
            model_version: model_state.version,
        };

        // 更新统计
        let mut stats = self.inference_stats.write().await;
        stats.successful_requests += 1;
        stats.average_processing_time = Duration::from_millis(
            ((stats.average_processing_time.as_millis() + processing_time.as_millis()) / 2) as u64,
        );

        info!(
            "推理完成: {} -> {:.4} (置信度: {:.4})",
            request.id, prediction, confidence
        );
        Ok(result)
    }

    async fn run_inference(&self, features: &[f64], model_state: &ModelState) -> f64 {
        // 模拟推理计算
        sleep(Duration::from_millis(10)).await;

        let mut result = model_state.bias;
        for (feature, weight) in features.iter().zip(model_state.weights.iter()) {
            result += feature * weight;
        }

        result.tanh()
    }

    pub async fn get_inference_stats(&self) -> InferenceStats {
        let mut stats = self.inference_stats.read().await.clone();
        stats.queue_size = self.inference_queue.read().await.len();
        stats
    }
}

/// 3. 异步数据处理管道
#[derive(Debug, Clone)]
pub struct AsyncDataPipeline {
    stages: Arc<RwLock<Vec<PipelineStage>>>,
    data_queue: Arc<RwLock<Vec<DataBatch>>>,
    pipeline_stats: Arc<RwLock<PipelineStats>>,
}

#[derive(Debug, Clone)]
pub struct PipelineStage {
    pub id: String,
    pub name: String,
    pub stage_type: StageType,
    pub config: HashMap<String, String>,
}

#[derive(Debug, Clone)]
pub enum StageType {
    Loader,
    Transformer,
    Filter,
    Aggregator,
    Sink,
}

#[derive(Debug, Clone)]
pub struct DataBatch {
    pub id: String,
    pub data: Vec<HashMap<String, f64>>,
    pub metadata: HashMap<String, String>,
    pub created_at: u64,
}

#[derive(Debug, Clone, Default)]
pub struct PipelineStats {
    pub total_batches: usize,
    pub processed_batches: usize,
    pub failed_batches: usize,
    pub average_processing_time: Duration,
}

impl AsyncDataPipeline {
    pub fn new() -> Self {
        Self {
            stages: Arc::new(RwLock::new(Vec::new())),
            data_queue: Arc::new(RwLock::new(Vec::new())),
            pipeline_stats: Arc::new(RwLock::new(PipelineStats::default())),
        }
    }

    pub async fn add_stage(&self, stage: PipelineStage) -> Result<()> {
        let mut stages = self.stages.write().await;
        stages.push(stage.clone());
        info!("添加管道阶段: {} ({})", stage.name, stage.id);
        Ok(())
    }

    pub async fn process_data(&self, batch: DataBatch) -> Result<()> {
        let start_time = Instant::now();

        // 将数据添加到队列
        {
            let mut queue = self.data_queue.write().await;
            queue.push(batch.clone());
        }

        // 获取所有阶段
        let stages = self.stages.read().await;
        let mut current_data = batch.data;

        // 按顺序处理每个阶段
        for stage in stages.iter() {
            current_data = self.execute_stage(&stage, current_data).await?;
            info!(
                "阶段 {} 处理完成，输出 {} 条记录",
                stage.name,
                current_data.len()
            );
        }

        let processing_time = start_time.elapsed();

        // 更新统计
        let mut stats = self.pipeline_stats.write().await;
        stats.processed_batches += 1;
        stats.average_processing_time = Duration::from_millis(
            ((stats.average_processing_time.as_millis() + processing_time.as_millis()) / 2) as u64,
        );

        info!("数据处理完成，耗时: {:?}", processing_time);
        Ok(())
    }

    async fn execute_stage(
        &self,
        stage: &PipelineStage,
        data: Vec<HashMap<String, f64>>,
    ) -> Result<Vec<HashMap<String, f64>>> {
        match stage.stage_type {
            StageType::Loader => self.execute_loader_stage(data).await,
            StageType::Transformer => self.execute_transformer_stage(data, &stage.config).await,
            StageType::Filter => self.execute_filter_stage(data, &stage.config).await,
            StageType::Aggregator => self.execute_aggregator_stage(data, &stage.config).await,
            StageType::Sink => self.execute_sink_stage(data).await,
        }
    }

    async fn execute_loader_stage(
        &self,
        data: Vec<HashMap<String, f64>>,
    ) -> Result<Vec<HashMap<String, f64>>> {
        // 模拟数据加载
        sleep(Duration::from_millis(20)).await;
        info!("加载了 {} 条记录", data.len());
        Ok(data)
    }

    async fn execute_transformer_stage(
        &self,
        data: Vec<HashMap<String, f64>>,
        config: &HashMap<String, String>,
    ) -> Result<Vec<HashMap<String, f64>>> {
        // 模拟数据转换
        sleep(Duration::from_millis(30)).await;

        let mut transformed_data = Vec::new();
        for record in data {
            let mut transformed_record = record.clone();

            // 添加新特征
            if let Some(feature_name) = config.get("new_feature") {
                let value =
                    transformed_record.values().sum::<f64>() / transformed_record.len() as f64;
                transformed_record.insert(feature_name.clone(), value);
            }

            transformed_data.push(transformed_record);
        }

        info!("转换了 {} 条记录", transformed_data.len());
        Ok(transformed_data)
    }

    #[allow(unused_variables)]
    async fn execute_filter_stage(
        &self,
        data: Vec<HashMap<String, f64>>,
        config: &HashMap<String, String>,
    ) -> Result<Vec<HashMap<String, f64>>> {
        // 模拟数据过滤
        sleep(Duration::from_millis(15)).await;

        let filtered_data: Vec<HashMap<String, f64>> = data
            .into_iter()
            .filter(|record| {
                // 简单的过滤逻辑
                record.values().any(|&v| v > 0.0)
            })
            .collect();

        info!("过滤后剩余 {} 条记录", filtered_data.len());
        Ok(filtered_data)
    }

    #[allow(unused_variables)]
    async fn execute_aggregator_stage(
        &self,
        data: Vec<HashMap<String, f64>>,
        config: &HashMap<String, String>,
    ) -> Result<Vec<HashMap<String, f64>>> {
        // 模拟数据聚合
        sleep(Duration::from_millis(25)).await;

        let mut aggregated_data = Vec::new();
        if !data.is_empty() {
            let mut aggregated_record = HashMap::new();

            // 计算平均值
            for key in data[0].keys() {
                let sum: f64 = data
                    .iter()
                    .map(|record| record.get(key).unwrap_or(&0.0))
                    .sum();
                let avg = sum / data.len() as f64;
                aggregated_record.insert(key.clone(), avg);
            }

            aggregated_data.push(aggregated_record);
        }

        info!("聚合后生成 {} 条记录", aggregated_data.len());
        Ok(aggregated_data)
    }

    #[allow(unused_variables)]
    async fn execute_sink_stage(
        &self,
        data: Vec<HashMap<String, f64>>,
    ) -> Result<Vec<HashMap<String, f64>>> {
        // 模拟数据输出
        sleep(Duration::from_millis(10)).await;
        info!("输出 {} 条记录", data.len());
        Ok(data)
    }

    pub async fn get_pipeline_stats(&self) -> PipelineStats {
        self.pipeline_stats.read().await.clone()
    }
}

#[tokio::main]
#[allow(unused_variables)]
async fn main() -> Result<()> {
    tracing_subscriber::fmt::init();

    info!("🚀 开始 2025 年异步机器学习模式演示");

    // 1. 演示异步模型训练
    info!("🧠 演示异步模型训练管理器");
    let config = TrainingConfig {
        model_name: "user_behavior_model".to_string(),
        learning_rate: 0.001,
        batch_size: 16,
        epochs: 20,
        validation_split: 0.2,
        early_stopping_patience: 5,
    };

    let (trainer, mut progress_receiver) = AsyncModelTrainer::new(config);

    // 生成训练数据
    let mut training_samples = Vec::new();
    for i in 0..100 {
        let features = (0..10).map(|_| rand::random::<f64>()).collect();
        let label = if i % 3 == 0 { 1.0 } else { 0.0 };

        training_samples.push(TrainingSample {
            id: format!("sample_{}", i),
            features,
            label,
            weight: Some(1.0),
        });
    }

    trainer.add_training_data(training_samples).await?;

    // 启动训练进度监控
    let trainer_clone = trainer.clone();
    let progress_task = tokio::spawn(async move {
        while let Some(progress) = progress_receiver.recv().await {
            info!(
                "训练进度 - Epoch {}: 准确率 {:.4}, 损失 {:.4}",
                progress.epoch, progress.accuracy, progress.loss
            );
        }
    });

    // 开始训练
    trainer.start_training().await?;
    drop(progress_task);

    let training_stats = trainer.get_training_stats().await;
    info!(
        "训练统计: 总样本 {}, 训练时间 {:?}, 最佳准确率 {:.4}",
        training_stats.total_samples, training_stats.training_time, training_stats.best_accuracy
    );

    // 2. 演示异步模型推理服务
    info!("🔮 演示异步模型推理服务");
    let inference_service = AsyncInferenceService::new(5);

    // 注册训练好的模型
    let model_state = trainer.get_model_state().await;
    inference_service
        .register_model("user_behavior_model".to_string(), model_state)
        .await?;

    // 提交推理请求
    let request_handles: Vec<String> = Vec::new();
    for i in 0..20 {
        let features = (0..10).map(|_| rand::random::<f64>()).collect();
        let request = InferenceRequest {
            id: format!("request_{}", i),
            model_name: "user_behavior_model".to_string(),
            features,
            priority: if i % 5 == 0 {
                InferencePriority::High
            } else {
                InferencePriority::Normal
            },
            created_at: std::time::SystemTime::now()
                .duration_since(std::time::UNIX_EPOCH)
                .unwrap()
                .as_secs(),
            timeout: Duration::from_secs(30),
        };

        inference_service.submit_inference_request(request).await?;
    }

    // 等待处理完成
    sleep(Duration::from_millis(500)).await;

    let inference_stats = inference_service.get_inference_stats().await;
    info!(
        "推理统计: 总请求 {}, 成功 {}, 失败 {}, 平均处理时间 {:?}",
        inference_stats.total_requests,
        inference_stats.successful_requests,
        inference_stats.failed_requests,
        inference_stats.average_processing_time
    );

    // 3. 演示异步数据处理管道
    info!("🔄 演示异步数据处理管道");
    let pipeline = AsyncDataPipeline::new();

    // 添加管道阶段
    pipeline
        .add_stage(PipelineStage {
            id: "loader".to_string(),
            name: "数据加载器".to_string(),
            stage_type: StageType::Loader,
            config: HashMap::new(),
        })
        .await?;

    pipeline
        .add_stage(PipelineStage {
            id: "transformer".to_string(),
            name: "数据转换器".to_string(),
            stage_type: StageType::Transformer,
            config: [("new_feature".to_string(), "computed_feature".to_string())]
                .iter()
                .cloned()
                .collect(),
        })
        .await?;

    pipeline
        .add_stage(PipelineStage {
            id: "filter".to_string(),
            name: "数据过滤器".to_string(),
            stage_type: StageType::Filter,
            config: HashMap::new(),
        })
        .await?;

    pipeline
        .add_stage(PipelineStage {
            id: "aggregator".to_string(),
            name: "数据聚合器".to_string(),
            stage_type: StageType::Aggregator,
            config: HashMap::new(),
        })
        .await?;

    pipeline
        .add_stage(PipelineStage {
            id: "sink".to_string(),
            name: "数据输出器".to_string(),
            stage_type: StageType::Sink,
            config: HashMap::new(),
        })
        .await?;

    // 处理数据批次
    for batch_id in 0..5 {
        let mut data = Vec::new();
        for i in 0..10 {
            let mut record = HashMap::new();
            record.insert("feature_1".to_string(), rand::random::<f64>());
            record.insert("feature_2".to_string(), rand::random::<f64>());
            record.insert("feature_3".to_string(), rand::random::<f64>());
            data.push(record);
        }

        let batch = DataBatch {
            id: format!("batch_{}", batch_id),
            data,
            metadata: HashMap::new(),
            created_at: std::time::SystemTime::now()
                .duration_since(std::time::UNIX_EPOCH)
                .unwrap()
                .as_secs(),
        };

        pipeline.process_data(batch).await?;
    }

    let pipeline_stats = pipeline.get_pipeline_stats().await;
    info!(
        "管道统计: 处理批次 {}, 平均处理时间 {:?}",
        pipeline_stats.processed_batches, pipeline_stats.average_processing_time
    );

    info!("✅ 2025 年异步机器学习模式演示完成!");

    Ok(())
}
