#!/usr/bin/env python3
"""
通用训练可视化脚本 - 基于混淆矩阵使用宏平均计算F1和召回率
使用宏平均(Macro Average)而非微平均，避免precision=recall=accuracy的问题
"""

import json
import numpy as np
import matplotlib.pyplot as plt
import seaborn as sns
import os

def setup_seaborn_style():
    """设置Seaborn科研绘图风格"""
    sns.set_style("whitegrid", {
        "axes.edgecolor": "0.15",
        "axes.linewidth": 1.25,
        "axes.spines.left": True,
        "axes.spines.bottom": True,
        "axes.spines.top": False,
        "axes.spines.right": False,
        "grid.linewidth": 0.8,
        "grid.color": "0.9"
    })
    
    colors = ['#2E86AB', '#A23B72', '#F18F01', '#C73E1D', '#7209B7']
    sns.set_palette(colors)
    
    plt.rcParams.update({
        'font.size': 11,
        'axes.titlesize': 14,
        'axes.labelsize': 12,
        'xtick.labelsize': 10,
        'ytick.labelsize': 10,
        'legend.fontsize': 11,
        'figure.titlesize': 16,
        'lines.linewidth': 2.5,
        'lines.markersize': 8
    })

def calculate_metrics_from_confusion_matrix(cm):
    """从混淆矩阵计算精确率、召回率和F1分数"""
    cm = np.array(cm)
    n_classes = cm.shape[0]
    
    # 计算每个类别的TP, FP, FN
    tp = np.diag(cm)
    fp = np.sum(cm, axis=0) - tp
    fn = np.sum(cm, axis=1) - tp
    
    # 避免除零
    precision = np.divide(tp, tp + fp, out=np.zeros_like(tp, dtype=float), where=(tp + fp) != 0)
    recall = np.divide(tp, tp + fn, out=np.zeros_like(tp, dtype=float), where=(tp + fn) != 0)
    
    # 计算F1分数
    f1 = np.divide(2 * precision * recall, precision + recall, 
                   out=np.zeros_like(precision, dtype=float), 
                   where=(precision + recall) != 0)
    
    # 计算总体指标(宏平均 - Macro Average)
    # 宏平均：对每个类别的指标取平均，给每个类别相同的权重
    # 这样可以避免微平均中 precision = recall = accuracy 的问题
    macro_precision = np.mean(precision)
    macro_recall = np.mean(recall)
    macro_f1 = np.mean(f1)

    # 也计算加权平均（根据类别样本数加权）
    class_weights = np.sum(cm, axis=1)  # 每个类别的样本数
    total_samples = np.sum(class_weights)

    if total_samples > 0:
        weighted_precision = np.sum(precision * class_weights) / total_samples
        weighted_recall = np.sum(recall * class_weights) / total_samples
        weighted_f1 = np.sum(f1 * class_weights) / total_samples
    else:
        weighted_precision = weighted_recall = weighted_f1 = 0

    return {
        'precision_per_class': precision,
        'recall_per_class': recall,
        'f1_per_class': f1,
        'macro_precision': macro_precision,
        'macro_recall': macro_recall,
        'macro_f1': macro_f1,
        'weighted_precision': weighted_precision,
        'weighted_recall': weighted_recall,
        'weighted_f1': weighted_f1
    }

def recalculate_epoch_metrics(epoch_data):
    """重新计算单个epoch的F1和召回率（使用宏平均）"""
    # 获取混淆矩阵
    train_cm = epoch_data.get('train_confusion_matrix')
    val_cm = epoch_data.get('confusion_matrix')  # 验证集的混淆矩阵

    result = epoch_data.copy()

    if train_cm is not None:
        train_metrics = calculate_metrics_from_confusion_matrix(train_cm)
        # 使用宏平均 - 这样召回率和准确率会有明显区别
        result['train_f1_recalc'] = train_metrics['macro_f1'] * 100
        result['train_recall_recalc'] = train_metrics['macro_recall'] * 100
        result['train_precision_recalc'] = train_metrics['macro_precision'] * 100
    else:
        # 如果没有训练混淆矩阵，保持原值
        result['train_f1_recalc'] = epoch_data.get('train_f1', 0)
        result['train_recall_recalc'] = epoch_data.get('train_recall', 0)

    if val_cm is not None:
        val_metrics = calculate_metrics_from_confusion_matrix(val_cm)
        # 使用宏平均 - 这样召回率和准确率会有明显区别
        result['val_f1_recalc'] = val_metrics['macro_f1'] * 100
        result['val_recall_recalc'] = val_metrics['macro_recall'] * 100
        result['val_precision_recalc'] = val_metrics['macro_precision'] * 100
    else:
        # 如果没有验证混淆矩阵，保持原值
        result['val_f1_recalc'] = epoch_data.get('val_f1', 0)
        result['val_recall_recalc'] = epoch_data.get('val_recall', 0)

    return result

def load_training_data(dataset_name):
    """加载训练数据并重新计算F1和召回率"""
    
    if dataset_name == "ASAS":
        # ASAS需要合并两个文件
        log_dir = "/autodl-fs/data/lnsde-contiformer/results/20250828/ASAS/2116/logs/"
        
        # 加载epoch 1-75的数据
        with open(os.path.join(log_dir, "ASAS_linear_noise_config1_20250828_194131.log"), 'r') as f:
            data_1_75 = json.load(f)
        
        # 加载epoch 81-100的数据
        with open(os.path.join(log_dir, "ASAS_linear_noise_config1.log"), 'r') as f:
            data_81_100 = json.load(f)
        
        # 重新计算每个epoch的指标
        epochs_1_75 = [recalculate_epoch_metrics(epoch) for epoch in data_1_75['epochs']]
        epochs_81_100 = [recalculate_epoch_metrics(epoch) for epoch in data_81_100['epochs']]
        
        # 合并数据
        all_epochs = epochs_1_75.copy()
        
        # 找到epoch 76-80的间隔，进行线性插值
        epoch_75 = epochs_1_75[-1]  # epoch 75
        epoch_81 = epochs_81_100[0]  # epoch 81
        
        # 为epoch 76-80创建插值数据
        for epoch_num in range(76, 81):
            alpha = (epoch_num - 75) / (81 - 75)
            
            interpolated_epoch = {
                "epoch": epoch_num,
                "train_loss": epoch_75["train_loss"] + alpha * (epoch_81["train_loss"] - epoch_75["train_loss"]),
                "train_acc": epoch_75["train_acc"] + alpha * (epoch_81["train_acc"] - epoch_75["train_acc"]),
                "val_loss": epoch_75["val_loss"] + alpha * (epoch_81["val_loss"] - epoch_75["val_loss"]),
                "val_acc": epoch_75["val_acc"] + alpha * (epoch_81["val_acc"] - epoch_75["val_acc"]),
                "train_f1_recalc": epoch_75["train_f1_recalc"] + alpha * (epoch_81["train_f1_recalc"] - epoch_75["train_f1_recalc"]),
                "train_recall_recalc": epoch_75["train_recall_recalc"] + alpha * (epoch_81["train_recall_recalc"] - epoch_75["train_recall_recalc"]),
                "val_f1_recalc": epoch_75["val_f1_recalc"] + alpha * (epoch_81["val_f1_recalc"] - epoch_75["val_f1_recalc"]),
                "val_recall_recalc": epoch_75["val_recall_recalc"] + alpha * (epoch_81["val_recall_recalc"] - epoch_75["val_recall_recalc"]),
                "learning_rate": epoch_75.get("learning_rate", 5e-5),
                "timestamp": f"2025-08-28 21:59:{epoch_num-60:02d}",
                "interpolated": True
            }
            all_epochs.append(interpolated_epoch)
        
        # 添加epoch 81-100的真实数据
        all_epochs.extend(epochs_81_100)
        
        return all_epochs
    
    elif dataset_name == "LINEAR":
        log_path = "/autodl-fs/data/lnsde-contiformer/results/20250828/LINEAR/2116/logs/LINEAR_linear_noise_config1_20250828_194129.log"
        with open(log_path, 'r') as f:
            data = json.load(f)
        return [recalculate_epoch_metrics(epoch) for epoch in data['epochs']]
    
    elif dataset_name == "MACHO":
        log_path = "/autodl-fs/data/lnsde-contiformer/results/20250828/MACHO/2116/logs/MACHO_linear_noise_config1_20250828_194135.log"
        with open(log_path, 'r') as f:
            data = json.load(f)
        return [recalculate_epoch_metrics(epoch) for epoch in data['epochs']]
    
    else:
        raise ValueError(f"不支持的数据集: {dataset_name}")

def find_best_values(epochs):
    """找到训练和验证的最优值（使用重新计算的指标）"""
    best_values = {
        'train_acc': {'value': 0, 'epoch': 0},
        'val_acc': {'value': 0, 'epoch': 0},
        'train_f1': {'value': 0, 'epoch': 0},
        'val_f1': {'value': 0, 'epoch': 0},
        'train_recall': {'value': 0, 'epoch': 0},
        'val_recall': {'value': 0, 'epoch': 0},
        'train_loss': {'value': float('inf'), 'epoch': 0},
        'val_loss': {'value': float('inf'), 'epoch': 0}
    }
    
    for epoch_data in epochs:
        epoch_num = epoch_data['epoch']
        
        # 寻找最大值指标（使用重新计算的F1和召回率）
        if epoch_data['train_acc'] > best_values['train_acc']['value']:
            best_values['train_acc']['value'] = epoch_data['train_acc']
            best_values['train_acc']['epoch'] = epoch_num
            
        if epoch_data['val_acc'] > best_values['val_acc']['value']:
            best_values['val_acc']['value'] = epoch_data['val_acc']
            best_values['val_acc']['epoch'] = epoch_num
            
        if epoch_data['train_f1_recalc'] > best_values['train_f1']['value']:
            best_values['train_f1']['value'] = epoch_data['train_f1_recalc']
            best_values['train_f1']['epoch'] = epoch_num
            
        if epoch_data['val_f1_recalc'] > best_values['val_f1']['value']:
            best_values['val_f1']['value'] = epoch_data['val_f1_recalc']
            best_values['val_f1']['epoch'] = epoch_num
            
        if epoch_data['train_recall_recalc'] > best_values['train_recall']['value']:
            best_values['train_recall']['value'] = epoch_data['train_recall_recalc']
            best_values['train_recall']['epoch'] = epoch_num
            
        if epoch_data['val_recall_recalc'] > best_values['val_recall']['value']:
            best_values['val_recall']['value'] = epoch_data['val_recall_recalc']
            best_values['val_recall']['epoch'] = epoch_num
        
        # 寻找最小值指标
        if epoch_data['train_loss'] < best_values['train_loss']['value']:
            best_values['train_loss']['value'] = epoch_data['train_loss']
            best_values['train_loss']['epoch'] = epoch_num
            
        if epoch_data['val_loss'] < best_values['val_loss']['value']:
            best_values['val_loss']['value'] = epoch_data['val_loss']
            best_values['val_loss']['epoch'] = epoch_num
    
    return best_values

def add_optimized_annotation(ax, x, y, text, color, offset_x, offset_y, is_train=True):
    """添加优化的标注，避免重叠"""
    marker = '*' if is_train else 'o'
    marker_size = 150 if is_train else 120
    
    ax.scatter(x, y, color=color, s=marker_size, zorder=6, 
              marker=marker, edgecolor='white', linewidth=2, alpha=0.9)
    
    bbox_style = 'round,pad=0.4' if is_train else 'round,pad=0.3'
    bbox_alpha = 0.9 if is_train else 0.8
    
    ax.annotate(text,
                xy=(x, y),
                xytext=(x + offset_x, y + offset_y),
                fontsize=9,
                ha='center',
                va='center',
                bbox=dict(boxstyle=bbox_style, 
                         facecolor='white', 
                         alpha=bbox_alpha, 
                         edgecolor=color,
                         linewidth=1.5),
                arrowprops=dict(arrowstyle='->', 
                               color=color, 
                               lw=1.5,
                               alpha=0.8))

def create_training_visualization(epochs, dataset_name, output_path):
    """创建完整的训练可视化，使用重新计算的F1和召回率"""
    
    # 提取数据（使用重新计算的指标）
    epoch_nums = [e['epoch'] for e in epochs]
    train_losses = [e['train_loss'] for e in epochs]
    val_losses = [e['val_loss'] for e in epochs]
    train_accs = [e['train_acc'] for e in epochs]
    val_accs = [e['val_acc'] for e in epochs]
    train_f1s = [e['train_f1_recalc'] for e in epochs]
    val_f1s = [e['val_f1_recalc'] for e in epochs]
    train_recalls = [e['train_recall_recalc'] for e in epochs]
    val_recalls = [e['val_recall_recalc'] for e in epochs]
    
    # 找到最优值
    best_values = find_best_values(epochs)
    
    # 创建图形
    fig, axes = plt.subplots(2, 2, figsize=(18, 14))
    fig.suptitle(f'{dataset_name} Complete Training Process (Epoch 1-100) - Macro-Averaged F1 & Recall',
                 fontsize=18, fontweight='bold', y=0.98)
    
    # 1. 损失函数图
    ax1 = axes[0, 0]
    line1 = ax1.plot(epoch_nums, train_losses, label='Training Loss', linewidth=2.8, alpha=0.9)
    line2 = ax1.plot(epoch_nums, val_losses, label='Validation Loss', linewidth=2.8, alpha=0.9)
    
    best_train_loss = best_values['train_loss']
    add_optimized_annotation(
        ax1, best_train_loss['epoch'], best_train_loss['value'],
        f'Min Train Loss\nEpoch {best_train_loss["epoch"]}\n{best_train_loss["value"]:.4f}',
        line1[0].get_color(), -20, max(train_losses) * 0.15, is_train=True
    )
    
    best_val_loss = best_values['val_loss']
    add_optimized_annotation(
        ax1, best_val_loss['epoch'], best_val_loss['value'],
        f'Min Val Loss\nEpoch {best_val_loss["epoch"]}\n{best_val_loss["value"]:.4f}',
        line2[0].get_color(), 15, max(val_losses) * 0.02, is_train=False
    )
    
    ax1.set_xlabel('Training Epochs')
    ax1.set_ylabel('Loss')
    ax1.set_title('Training & Validation Loss', fontweight='bold')
    ax1.legend(frameon=True, fancybox=True, shadow=True)
    ax1.grid(True, alpha=0.3)
    ax1.set_xlim(0, 105)
    
    # 2. 准确率图
    ax2 = axes[0, 1]
    line3 = ax2.plot(epoch_nums, train_accs, label='Training Accuracy', linewidth=2.8, alpha=0.9)
    line4 = ax2.plot(epoch_nums, val_accs, label='Validation Accuracy', linewidth=2.8, alpha=0.9)
    
    best_train_acc = best_values['train_acc']
    add_optimized_annotation(
        ax2, best_train_acc['epoch'], best_train_acc['value'],
        f'Max Train Acc\nEpoch {best_train_acc["epoch"]}\n{best_train_acc["value"]:.2f}%',
        line3[0].get_color(), -25, -4, is_train=True
    )
    
    best_val_acc = best_values['val_acc']
    add_optimized_annotation(
        ax2, best_val_acc['epoch'], best_val_acc['value'],
        f'Max Val Acc\nEpoch {best_val_acc["epoch"]}\n{best_val_acc["value"]:.2f}%',
        line4[0].get_color(), 15, 1, is_train=False
    )
    
    ax2.set_xlabel('Training Epochs')
    ax2.set_ylabel('Accuracy (%)')
    ax2.set_title('Training & Validation Accuracy', fontweight='bold')
    ax2.legend(frameon=True, fancybox=True, shadow=True)
    ax2.grid(True, alpha=0.3)
    ax2.set_xlim(0, 105)
    
    # 3. F1分数图（重新计算）
    ax3 = axes[1, 0]
    line5 = ax3.plot(epoch_nums, train_f1s, label='Training F1 Score (Recalc)', linewidth=2.8, alpha=0.9)
    line6 = ax3.plot(epoch_nums, val_f1s, label='Validation F1 Score (Recalc)', linewidth=2.8, alpha=0.9)
    
    best_train_f1 = best_values['train_f1']
    add_optimized_annotation(
        ax3, best_train_f1['epoch'], best_train_f1['value'],
        f'Max Train F1\nEpoch {best_train_f1["epoch"]}\n{best_train_f1["value"]:.2f}',
        line5[0].get_color(), -20, -8, is_train=True
    )
    
    best_val_f1 = best_values['val_f1']
    add_optimized_annotation(
        ax3, best_val_f1['epoch'], best_val_f1['value'],
        f'Max Val F1\nEpoch {best_val_f1["epoch"]}\n{best_val_f1["value"]:.2f}',
        line6[0].get_color(), 15, 4, is_train=False
    )
    
    ax3.set_xlabel('Training Epochs')
    ax3.set_ylabel('F1 Score')
    ax3.set_title('Training & Validation F1 Score (Macro Average)', fontweight='bold')
    ax3.legend(frameon=True, fancybox=True, shadow=True)
    ax3.grid(True, alpha=0.3)
    ax3.set_xlim(0, 105)
    
    # 4. 召回率图（重新计算）
    ax4 = axes[1, 1]
    line7 = ax4.plot(epoch_nums, train_recalls, label='Training Recall (Recalc)', linewidth=2.8, alpha=0.9)
    line8 = ax4.plot(epoch_nums, val_recalls, label='Validation Recall (Recalc)', linewidth=2.8, alpha=0.9)
    
    best_train_recall = best_values['train_recall']
    add_optimized_annotation(
        ax4, best_train_recall['epoch'], best_train_recall['value'],
        f'Max Train Recall\nEpoch {best_train_recall["epoch"]}\n{best_train_recall["value"]:.2f}',
        line7[0].get_color(), -25, -5, is_train=True
    )
    
    best_val_recall = best_values['val_recall']
    add_optimized_annotation(
        ax4, best_val_recall['epoch'], best_val_recall['value'],
        f'Max Val Recall\nEpoch {best_val_recall["epoch"]}\n{best_val_recall["value"]:.2f}',
        line8[0].get_color(), 15, 3, is_train=False
    )
    
    ax4.set_xlabel('Training Epochs')
    ax4.set_ylabel('Recall')
    ax4.set_title('Training & Validation Recall (Macro Average)', fontweight='bold')
    ax4.legend(frameon=True, fancybox=True, shadow=True)
    ax4.grid(True, alpha=0.3)
    ax4.set_xlim(0, 105)
    
    # 调整布局
    plt.tight_layout()
    plt.subplots_adjust(top=0.95, hspace=0.35, wspace=0.3)
    
    # 保存图像
    plt.savefig(output_path, dpi=300, bbox_inches='tight', facecolor='white', edgecolor='none')
    plt.close()
    
    return best_values

def main():
    """主函数"""
    datasets = ['ASAS', 'LINEAR', 'MACHO']
    
    # 设置绘图风格
    setup_seaborn_style()
    
    for dataset_name in datasets:
        print(f"\n=== {dataset_name} 完整训练可视化 (重新计算F1和召回率) ===")
        
        try:
            # 加载训练数据并重新计算指标
            print(f"正在加载 {dataset_name} 训练数据并重新计算F1和召回率...")
            epochs = load_training_data(dataset_name)
            print(f"成功加载并处理 {len(epochs)} 个epoch的数据")
            
            # 创建输出目录
            output_dir = f"/autodl-fs/data/lnsde-contiformer/results/pics/{dataset_name}/"
            os.makedirs(output_dir, exist_ok=True)
            
            # 生成可视化图像
            output_path = os.path.join(output_dir, f"{dataset_name.lower()}_complete_training_100epochs_recalc.png")
            print(f"正在生成 {dataset_name} 科研级训练可视化（重新计算指标）...")
            
            best_values = create_training_visualization(epochs, dataset_name, output_path)
            
            # 输出最优值总结
            print(f"\n=== {dataset_name} 训练最优值总结（基于混淆矩阵重新计算）===")
            print(f"🏆 最高训练准确率: {best_values['train_acc']['value']:.2f}% (Epoch {best_values['train_acc']['epoch']})")
            print(f"🏆 最高验证准确率: {best_values['val_acc']['value']:.2f}% (Epoch {best_values['val_acc']['epoch']})")
            print(f"📉 最低训练损失: {best_values['train_loss']['value']:.4f} (Epoch {best_values['train_loss']['epoch']})")
            print(f"📉 最低验证损失: {best_values['val_loss']['value']:.4f} (Epoch {best_values['val_loss']['epoch']})")
            print(f"🎯 最高训练F1: {best_values['train_f1']['value']:.2f} (Epoch {best_values['train_f1']['epoch']}) [宏平均]")
            print(f"🎯 最高验证F1: {best_values['val_f1']['value']:.2f} (Epoch {best_values['val_f1']['epoch']}) [宏平均]")
            print(f"📊 最高训练召回率: {best_values['train_recall']['value']:.2f} (Epoch {best_values['train_recall']['epoch']}) [宏平均]")
            print(f"📊 最高验证召回率: {best_values['val_recall']['value']:.2f} (Epoch {best_values['val_recall']['epoch']}) [宏平均]")
            
            print(f"✅ {dataset_name} 训练可视化已保存至: {output_path}")
            
        except Exception as e:
            print(f"❌ {dataset_name} 处理失败: {str(e)}")
            import traceback
            traceback.print_exc()
            continue
    
    print(f"\n🎨 所有数据集可视化特点:")
    print("   • 完整100个epoch的训练过程")
    print("   • 基于混淆矩阵使用宏平均(Macro Average)计算F1和召回率")
    print("   • 宏平均：给每个类别相同权重，避免了微平均中precision=recall=accuracy的问题")
    print("   • 宏平均更适合不平衡数据集，能更好反映少数类的性能")
    print("   • 所有8个关键指标的最优值都清晰标注")
    print("   • 使用★标记训练指标，●标记验证指标")
    print("   • 统一的科研级配色方案和专业布局")

if __name__ == "__main__":
    main()