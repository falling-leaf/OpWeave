#pragma once
#ifndef _GPU_LOAD_PREDICTOR_H_
#define _GPU_LOAD_PREDICTOR_H_

#include <torch/torch.h>
#include <vector>
#include <string>

extern "C" {
#include "postgres.h"
}

class GPULoadPredictor {
public:
    GPULoadPredictor();
    ~GPULoadPredictor();

    bool TrainModel();
    bool LoadModel(const std::string& model_path);
    bool SaveModel(const std::string& model_path);

    // Set training data table name
    void SetTrainingTable(const std::string& table_name) { training_table_ = table_name; }

    double Predict(
        const std::vector<double>& workload,
        const std::vector<double>& gpu_resource
    );

    bool ExtractTrainingData(
        std::vector<std::vector<double>>& workloads,
        std::vector<std::vector<double>>& resources,
        std::vector<double>& targets
    );

private:
    bool model_loaded_;
    std::string training_table_;

    std::vector<double> workload_mean_;
    std::vector<double> workload_std_;
    std::vector<double> resource_mean_;
    std::vector<double> resource_std_;
    double target_mean_;
    double target_std_;

    void ComputeNormalizationParams(
        const std::vector<std::vector<double>>& workloads,
        const std::vector<std::vector<double>>& resources,
        const std::vector<double>& targets
    );

    torch::Tensor NormalizeWorkload(const std::vector<std::vector<double>>& data);
    torch::Tensor NormalizeResource(const std::vector<std::vector<double>>& data);
    torch::Tensor NormalizeTarget(const std::vector<double>& data);

    class RuntimeModelImpl : public torch::nn::Module {
    public:
        RuntimeModelImpl();
        void InitializeWeights();

        torch::Tensor forward(
            torch::Tensor workload_x,
            torch::Tensor resource_x
        );

        int hidden_dim() const { return hidden_dim_; }

    private:
        torch::nn::Linear w_fc1{nullptr};
        torch::nn::Linear w_fc2{nullptr};

        torch::nn::Linear r_fc1{nullptr};
        torch::nn::Linear r_fc2{nullptr};

        torch::nn::Linear mlp{nullptr};
        torch::nn::Linear mlp2{nullptr};
        torch::nn::Linear output{nullptr};

        int hidden_dim_;
    };

    TORCH_MODULE(RuntimeModel);
    RuntimeModel model_;
};

#endif  // _GPU_LOAD_PREDICTOR_H_
