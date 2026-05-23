# Appliances Energy Prediction
from ucimlrepo import fetch_ucirepo 
import numpy as np
import torch

import sys
import os
from pathlib import Path

PROJECT_ROOT = Path(__file__).resolve().parents[2]
if str(PROJECT_ROOT) not in sys.path:
    sys.path.insert(0, str(PROJECT_ROOT))

from djgp.evaluation.calibration import pack_gaussian_uq_list  # noqa: E402

import time
from sklearn.decomposition import PCA
from sklearn.preprocessing import StandardScaler

from shared.djgp_validation import *
from argparse import Namespace
from shared.jumpgp_runner import *
from shared.deepgp import *

# 添加父级目录到系统路径
# sys.path.append(os.path.dirname(os.path.dirname(os.path.abspath(__file__))))
# 添加父级目录到系统路径

# 然后导入 JumpGP
from jumpgp import JumpGP

use_jgp_sir = False
use_jgp_pca = False
use_jgp = False
use_lmjgp = True
use_dgp = False

motivation = 'see_K_influence'

from sklearn.preprocessing import StandardScaler
from scipy.linalg import eigh
import numpy as np

import pickle
from datetime import datetime
import random

def sir_reduction(X, y, H=10, K=5):
    """
    执行 SIR 降维
    
    参数:
    X: 输入特征矩阵
    y: 目标变量（需要确保是1维数组）
    H: 分箱数量
    K: 目标维度
    """
    # 确保y是1维数组
    y = np.asarray(y).ravel()
    
    # 标准化特征
    scaler = StandardScaler()
    X_std = scaler.fit_transform(X)
    
    # 处理可能的无穷大和NaN值
    X_std = np.nan_to_num(X_std, nan=0.0, posinf=0.0, neginf=0.0)
    
    # 使用percentile进行分箱
    percentiles = np.linspace(0, 100, H+1)[1:-1]
    bin_edges = np.percentile(y, percentiles)
    y_binned = np.digitize(y, bin_edges)
    
    # 计算每个箱子的均值和比例
    means = np.zeros((H, X.shape[1]))
    props = np.zeros(H)
    for h in range(H):
        idx = (y_binned == h)
        if np.any(idx):  # 确保该箱子有数据
            means[h] = np.nan_to_num(X_std[idx].mean(axis=0))
            props[h] = idx.mean()
    
    # 标准化props以确保和为1
    props = props / np.sum(props)
    
    # 计算切片协方差矩阵
    m = np.zeros_like(means[0])
    V = np.zeros((X.shape[1], X.shape[1]))
    for h in range(H):
        if props[h] > 0:  # 只处理非空箱子
            diff = means[h] - m
            V += props[h] * np.outer(diff, diff)
    
    # 添加小的正则化项以确保数值稳定性
    V += 1e-8 * np.eye(V.shape[0])
    
    # 求解特征值问题
    try:
        eigvals, eigvecs = eigh(V)
    except np.linalg.LinAlgError:
        # 如果还是失败，使用SVD作为备选方案
        _, eigvecs = np.linalg.svd(V)[:2]
        eigvecs = eigvecs.T
    
    # 选择前K个特征向量
    selected_vecs = eigvecs[:, -K:]
    
    # 转换数据
    X_transformed = X_std @ selected_vecs
    
    return X_transformed, selected_vecs, scaler


# ... rest of your existing code ...
def main():
    total_res = {} 
    Erosion_res = {}
    num_exp = 10
    # dataset_candidates = ['Wine Quality', 'Parkinsons Telemonitoring', 'Appliances Energy Prediction']
    # dataset_candidates = ['Parkinsons Telemonitoring']
    # dtname = 'Parkinsons'
    dataset_candidates = ['Appliances Energy Prediction']
    dtname = 'Appliances'
    partdata_name = f'valtest_minibatch_lmjgp_res_erosion_{dtname}'
    fulldata_name = f'valtest_minibatch_total_res_{dtname}'

    # num_exp = 1 
    # dataset_candidates = ['Wine Quality']
    for dataset_name in dataset_candidates:
        total_res[dataset_name] = {}
        for seed in range(num_exp):
            np.random.seed(seed)
            torch.manual_seed(seed)
            random.seed(seed)
            
            if dataset_name == 'Appliances Energy Prediction':
                # fetch dataset 
                appliances_energy_prediction = fetch_ucirepo(id=374) 
                
                # data (as pandas dataframes) 
                X = appliances_energy_prediction.data.features 
                y = appliances_energy_prediction.data.targets 
                
                # metadata 
                print(appliances_energy_prediction.metadata) 
                
                # variable information 
                print(appliances_energy_prediction.variables) 

                X_np = X.iloc[:, 1:].to_numpy()
                y_np = y.to_numpy()

                # np.random.seed(seed)
                indices = np.random.permutation(X_np.shape[0])
                # split = int(X_np.shape[0] * 0.97)
                train_frac = 0.98
                val_frac = 0.01
                test_frac = 1- train_frac - val_frac

                split_train = int(X_np.shape[0] * train_frac)
                split_val = split_train + int(X_np.shape[0] * val_frac)

                train_idx, val_idx, test_idx = indices[:split_train], indices[split_train:split_val], indices[split_val:]
                X_train_np, X_val_np, X_test_np = X_np[train_idx], X_np[val_idx], X_np[test_idx]
                y_train_np, y_val_np, y_test_np = y_np[train_idx], y_np[val_idx], y_np[test_idx]

                X_train = torch.from_numpy(X_train_np).float()
                Y_train = torch.from_numpy(y_train_np).float()
                X_val = torch.from_numpy(X_val_np).float()
                Y_val = torch.from_numpy(y_val_np).float()
                X_test  = torch.from_numpy(X_test_np).float()
                Y_test  = torch.from_numpy(y_test_np).float()

                # 输出形状验证
                print("X_train:", X_train.shape)
                print("y_train:", Y_train.shape)
                print("X_test: ", X_test.shape)
                print("y_test: ", Y_test.shape)

                K = 5
            elif dataset_name == 'Parkinsons Telemonitoring':
                # Parkinsons Telemonitoring
                # fetch dataset 
                parkinsons_telemonitoring = fetch_ucirepo(id=189) 
                
                # data (as pandas dataframes) 
                X = parkinsons_telemonitoring.data.features 
                y = parkinsons_telemonitoring.data.targets 
                
                # metadata 
                print(parkinsons_telemonitoring.metadata) 
                
                # variable information 
                print(parkinsons_telemonitoring.variables) 
                
                X_np = X.to_numpy()
                y_np = y.to_numpy()
                indices = np.random.permutation(X_np.shape[0])
                split = int(X_np.shape[0] * 0.9)

                train_idx, test_idx = indices[:split], indices[split:]
                X_train_np, X_test_np = X_np[train_idx,:-1], X_np[test_idx,:-1]
                y_train_np, y_test_np = y_np[train_idx, 0], y_np[test_idx, 0]

                X_train = torch.from_numpy(X_train_np).float()
                Y_train = torch.from_numpy(y_train_np).float()
                X_test  = torch.from_numpy(X_test_np).float()
                Y_test  = torch.from_numpy(y_test_np).float()

                # 输出形状验证
                print("X_train:", X_train.shape)
                print("y_train:", Y_train.shape)
                print("X_test: ", X_test.shape)
                print("y_test: ", Y_test.shape)
                K = 5
            elif dataset_name == 'Wine Quality':
                wine_quality = fetch_ucirepo(id=186) 
            
                # data (as pandas dataframes) 
                X = wine_quality.data.features 
                y = wine_quality.data.targets 
                
                # metadata 
                print(wine_quality.metadata) 
                
                # variable information 
                print(wine_quality.variables) 

                # np.random.seed(seed)
                X_np = X.to_numpy()
                y_np = y.to_numpy()
                indices = np.random.permutation(X_np.shape[0])
                split = int(X_np.shape[0] * 0.9)

                train_idx, test_idx = indices[:split], indices[split:]
                X_train_np, X_test_np = X_np[train_idx,:], X_np[test_idx,:]
                y_train_np, y_test_np = y_np[train_idx, 0], y_np[test_idx, 0]

                X_train = torch.from_numpy(X_train_np).float()
                Y_train = torch.from_numpy(y_train_np).float()
                X_test  = torch.from_numpy(X_test_np).float()
                Y_test  = torch.from_numpy(y_test_np).float()

                # 输出形状验证
                print("X_train:", X_train.shape)
                print("y_train:", Y_train.shape)
                print("X_test: ", X_test.shape)
                print("y_test: ", Y_test.shape)
                K = 3

            res = {}
            H = 10  # 分箱数量

            # 对训练集和测试集应用SIR
            if use_jgp_sir:
                start_time = time.time()
                X_train_sir, sir_vecs, scaler = sir_reduction(X_train_np, y_train_np, H=H, K=K)
                X_test_sir = scaler.transform(X_test_np) @ sir_vecs

                JGP = JumpGP(X_train_sir, y_train_np, X_test_sir, L=1, M=20, mode='CEM', bVerbose=False)
                JGP.fit()
                rmse, mean_crps = JGP.metrics(y_test_np)
                print(f"RMSE: {rmse}, Mean CRPS: {mean_crps}")
                end_time = time.time()
                run_time = end_time - start_time

                res['jgp_sir'] = [rmse, mean_crps, run_time]

            if use_jgp_pca:
                start_time = time.time()
                scaler = StandardScaler()
                X_train_std = scaler.fit_transform(X_train_np)
                X_test_std = scaler.transform(X_test_np)

                # 2. PCA降维
                n_components = K  # 降到5维
                pca = PCA(n_components=n_components)
                X_train_pca = pca.fit_transform(X_train_std)
                X_test_pca = pca.transform(X_test_std)

                JGP = JumpGP(X_train_pca, y_train_np, X_test_pca, L=1, M=20, mode='CEM', bVerbose=False)
                JGP.fit()
                rmse, mean_crps = JGP.metrics(y_test_np)
                print(f"RMSE: {rmse}, Mean CRPS: {mean_crps}")
                end_time = time.time()
                run_time = end_time - start_time

                res['jgp_pca'] = [rmse, mean_crps, run_time]

            if use_jgp:
                start_time = time.time()
                JGP = JumpGP(X_train_np, y_train_np, X_test_np, L=1, M=20, mode='CEM', bVerbose=False)
                JGP.fit()
                rmse, mean_crps = JGP.metrics(y_test_np)
                print(f"RMSE: {rmse}, Mean CRPS: {mean_crps}")
                end_time = time.time()
                run_time = end_time - start_time

                res['jgp_raw'] = [rmse, mean_crps, run_time]

            if use_lmjgp:
                lmjgp_res = []
                # use_batch = True
                use_batch = False
                # for batch_size in [32,64, 128, 256]:
                for K in [2, 3, 5, 7]:
                    batch_size = 128
                    m1 = 4
                    # for m2 in [60]:
                    m2 = 60
                    # for lr in [0.001, 0.01, 0.05]:
                    for lr in [0.1]:
                        n = 45
                        # batch_size = 64
                        args = Namespace(
                            epochs=100,           # 训练轮数
                            num_epochs=300,
                            batch_size=batch_size,
                            hidden_dim=2,
                            lr=lr,
                            print_freq=10,        # 每多少个 epoch 打印一次信息
                            # save_path="./model",  # 模型保存路径（可选）
                            Q = K,
                            m1 = m1,
                            m2 = m2,
                            n = n,
                            num_steps = 200,
                            MC_num = 3,
                            eval=True,            # 是否评估模型性能
                            patience=10,          # 提前停止的耐心轮数
                            clip_grad=1.0,        # 梯度裁剪（可选）
                            use_batch = False
                        )
                        device = torch.device('cuda' if torch.cuda.is_available() else 'cpu')
                        X_train = X_train.float().to(device)
                        Y_train = Y_train.float().squeeze(-1).to(device)
                        X_test = X_test.float().to(device)
                        Y_test = Y_test.float().squeeze(-1).to(device)

                        X_val = X_val.float().to(device)
                        Y_val = Y_val.float().squeeze(-1).to(device)

                        # X_val = X_test
                        # Y_val = Y_test

                        N_test, D = X_test.shape
                        T         = N_test
                        Q         = args.Q
                        m1        = args.m1
                        m2        = args.m2
                        n         = args.n
                        num_steps = args.num_steps
                        MC_num    = args.MC_num

                        start_time = time.time()
                        # 4. Build neighborhoods (on CPU) then move to GPU
                        neighborhoods = find_neighborhoods(
                            X_test.cpu(), X_train.cpu(), Y_train.cpu(), M=n
                        )
                        regions = []
                        start_time = time.time()
                        for i in range(T):
                            X_nb = neighborhoods[i]['X_neighbors'].to(device)  # (n, D)
                            y_nb = neighborhoods[i]['y_neighbors'].to(device)  # (n,)
                            regions.append({
                                'X': X_nb,
                                'y': y_nb,
                                'C': torch.randn(m1, Q, device=device)       # random init
                            })

                        from shared.djgp_validation import construct_regions
                        regions_val = construct_regions(X_val, X_train, Y_train, M=n, device=device)
                        regions_data = (regions_val, X_val, Y_val)

                        # 5. Initialize V_params on GPU
                        V_params = {
                            'mu_V':    torch.randn(m2, Q, D, device=device, requires_grad=True),
                            'sigma_V': torch.rand( m2, Q, D, device=device, requires_grad=True),
                        }

                        # 6. Initialize u_params on GPU
                        u_params = []
                        for _ in range(T):
                            u_params.append({
                                'U_logit':    torch.zeros(1, device=device, requires_grad=True),
                                'mu_u':       torch.randn(m1, device=device, requires_grad=True),
                                'Sigma_u':    torch.eye(m1, device=device, requires_grad=True),
                                'sigma_noise':torch.tensor(0.5, device=device, requires_grad=True),
                                'sigma_k':torch.tensor(0.5, device=device, requires_grad=True),
                                'omega':      torch.randn(Q+1, device=device, requires_grad=True),
                            })

                        # 7. Initialize hyperparams on GPU
                        X_train_mean = X_train.mean(dim=0)
                        X_train_std  = X_train.std(dim=0)
                        Z = X_train_mean + torch.randn(m2, D, device=device) * X_train_std

                        hyperparams = {
                            'Z':            Z,                      # (m2, D)
                            'X_test':       X_test,                 # (T, D)
                            'lengthscales':torch.rand(Q, device=device, requires_grad=True),
                            'var_w':        torch.tensor(1.0, device=device, requires_grad=True),
                        }

                        print("Everything set!")

                        # 8. Compute ELBO, backprop, train, predict
                        # L = compute_ELBO(regions, V_params, u_params, hyperparams)
                        # print("ELBO L =", L.item())
                        # L.backward()
                        # print("Gradients OK")
                        if not use_batch or batch_size is None:
                            V_params, u_params, hyperparams = train_vi(
                                regions=regions,
                                V_params=V_params,
                                u_params=u_params,
                                hyperparams=hyperparams,
                                lr=args.lr,
                                num_steps=num_steps,
                                log_interval=50,
                                # regions_data=regions_data
                            )
                        else:
                            V_params, u_params, hyperparams, training_log, (best_val_V, best_val_u, best_val_hyp) = train_vi_minibatch(
                                regions=regions,
                                V_params=V_params,
                                u_params=u_params,
                                hyperparams=hyperparams,
                                lr=args.lr,
                                num_steps=num_steps,
                                log_interval=50,
                                batch_size=batch_size,
                                # regions_data=regions_data
                            )
                        print("train OK")
                        print(training_log)

                        mu_pred, var_pred = predict_vi(
                            regions, V_params, hyperparams, M=MC_num
                        )
                        print("Prediction OK")

                        # print("mu_pred:", mu_pred.shape)
                        # print("var_pred:", var_pred.shape)

                        # 9. Compute metrics & runtime
                        sigmas = torch.sqrt(var_pred)
                        rmse, mean_crps = compute_metrics(mu_pred, sigmas, Y_test)
                        end_time = time.time()
                        run_time = end_time - start_time
                        y_np = Y_test.detach().cpu().numpy()
                        mu_np = mu_pred.detach().cpu().numpy()
                        sig_np = sigmas.detach().cpu().numpy()
                        res["lmjgp"] = pack_gaussian_uq_list(
                            float(rmse.item()),
                            float(mean_crps.item()),
                            run_time,
                            y_np,
                            mu_np,
                            sig_np,
                        )
                        print(
                            f"Results [rmse, mean_crps, wall_sec, cov90, w90, cov95, w95]:{res['lmjgp']}"
                        )

                        # mu_pred_val, var_pred_val = predict_vi(
                        #     regions, best_val_V, best_val_hyp, M=MC_num
                        # )

                        # sigmas_val = torch.sqrt(var_pred_val)
                        # rmse_val, mean_crps_val = compute_metrics(mu_pred_val, sigmas_val, Y_test)
                        # print(f"Results [rmse, mean crps, runtime]:{[rmse_val, mean_crps_val]}")

                        # res['lmjgp-val'] = [rmse_val, mean_crps_val, run_time]
                        # print(f"comparison between train and use_val: train: {[rmse, mean_crps]}, use_val: {[rmse_val, mean_crps_val]}")

                        # res['lmjgp'] = [rmse, mean_crps, run_time]
                        # lmjgp_res.append({'m1': m1, 'm2': m2, 'rmse': rmse, 'mean_crps': mean_crps, 'run_time': run_time, 'n': n, 'batch_size': batch_size, 'lr': lr, 'training_log': training_log, 'res_val': res['lmjgp-val']})

                        lmjgp_res.append({'m1': m1, 'm2': m2, 'rmse': float(rmse.item()), 'mean_crps': float(mean_crps.item()), 'run_time': run_time, 'n': n, 'batch_size': batch_size, 'lr': lr, 'K': K})

            if use_dgp:
                args = Namespace(
                    epochs=100,           # 训练轮数
                    num_epochs=300,
                    batch_size=128,
                    hidden_dim=10,
                    lr=0.01,
                    print_freq=10,        # 每多少个 epoch 打印一次信息
                    # save_path="./model",  # 模型保存路径（可选）
                    eval=True,            # 是否评估模型性能
                    patience=30,          # 提前停止的耐心轮数
                    clip_grad=1.0,        # 梯度裁剪（可选）
                    # 如果你的 train_model 用了更多字段，也可以在这里继续加
                )

                # X_train = X_train.float().to(device)
                # Y_train = Y_train.float().squeeze(-1).to(device)
                # X_test = X_test.float().to(device)
                # Y_test = Y_test.float().squeeze(-1).to(device)

                # 创建数据加载器
                batch_size, hidden_dim, lr = 128, 2, 0.01
                train_dataset = TensorDataset(X_train, Y_train)
                test_dataset = TensorDataset(X_test, Y_test)
                train_loader = DataLoader(train_dataset, batch_size=batch_size, shuffle=True)
                test_loader = DataLoader(test_dataset, batch_size=batch_size)

                # 初始化模型
                model = DeepGP(X_train.shape, hidden_dim).to(device)

                # 初始化优化器和损失函数
                optimizer = torch.optim.Adam([{'params': model.parameters()}], lr=lr)
                mll = DeepApproximateMLL(VariationalELBO(model.likelihood, model, X_train.shape[-2]))

                # 训练模型
                final_metrics = train_model(model, train_loader, test_loader, optimizer, mll, args)


                res['djgp'] = final_metrics

                # res['training_log'] = training_log
            print(res)

            total_res[dataset_name][seed] = res
            timestamp = datetime.now().strftime('%Y%m%d_%H%M%S')
            filename = f'{motivation}_total_res_{timestamp}.pkl'

            # 保存数据
            with open(filename, 'wb') as f:
                pickle.dump(total_res, f)

            print(lmjgp_res)
            with open(f'{partdata_name}_{timestamp}.pkl', 'wb') as f:
                pickle.dump(lmjgp_res, f)

            Erosion_res[seed] = lmjgp_res

    filename = f'{motivation}_erosion_new_{dtname}.pkl'

    # 保存数据
    with open(filename, 'wb') as f:
        pickle.dump(total_res, f)

    with open(f'{fulldata_name}.pkl', 'wb') as f:
        pickle.dump(Erosion_res, f)
    return total_res, Erosion_res


if __name__ == "__main__":
    main()
