import argparse
import csv
import os
from functools import partial
from typing import Any, Callable, Optional, Union

import torch
import torch.nn as nn
import torch.optim as optim
from torch import Tensor
import torchvision
import torchvision.transforms as transforms
from torch.utils.data import DataLoader

# ==========================================
# 1. ORIGINAL ACTIVATION DEFINITIONS
# ==========================================
class Tanhexp(nn.Module):
    def forward(self, x: Tensor) -> Tensor:
        return x * torch.tanh(torch.exp(x))


# ==========================================
# 2. HARDWARE LUT ACTIVATION DEFINITIONS
# ==========================================
class HardwareLUTActivation(nn.Module):
    def __init__(self, csv_filename: str = "verilog_results.csv", column_idx: int = 3):
        super().__init__()
        
        if not os.path.exists(csv_filename):
            raise FileNotFoundError(f"Could not find hardware file: {csv_filename}")

        x_vals, y_vals = [], []
        with open(csv_filename, 'r') as f:
            reader = csv.reader(f)
            next(reader)
            for row in reader:
                x_vals.append(float(int(row[0]) / 1024.0))
                y_vals.append(float(int(row[column_idx]) / 1024.0))

        self.register_buffer("x_grid", torch.tensor(x_vals, dtype=torch.float32))
        self.register_buffer("y_grid", torch.tensor(y_vals, dtype=torch.float32))

    def get_lut_output(self, x: Tensor) -> Tensor:
        x_clamped = torch.clamp(x, min=self.x_grid[0], max=self.x_grid[-1])
        indices = torch.searchsorted(self.x_grid, x_clamped.contiguous()) - 1
        indices = torch.clamp(indices, min=0, max=len(self.x_grid) - 2)

        x0, x1 = self.x_grid[indices], self.x_grid[indices + 1]
        y0, y1 = self.y_grid[indices], self.y_grid[indices + 1]

        t = (x_clamped - x0) / (x1 - x0 + 1e-8)
        return y0 + t * (y1 - y0)

    def forward(self, x: Tensor) -> Tensor:
        # Default behavior for original HDC classes
        return self.get_lut_output(x)

# --- HDC Classes (Unchanged) ---
class HardwareSwish(HardwareLUTActivation):
    def __init__(self, csv_filename: str = "verilog_results.csv"):
        super().__init__(csv_filename=csv_filename, column_idx=1)

class HardwareGELU(HardwareLUTActivation):
    def __init__(self, csv_filename: str = "verilog_results.csv"):
        super().__init__(csv_filename=csv_filename, column_idx=2)

class HardwareTanhexp(HardwareLUTActivation):
    def __init__(self, csv_filename: str = "verilog_results.csv"):
        super().__init__(csv_filename=csv_filename, column_idx=3)

# --- CGP Classes ---
class CGPHardwareSwish(HardwareLUTActivation):
    def __init__(self, csv_filename: str = "cgp_results2.csv"):
        super().__init__(csv_filename=csv_filename, column_idx=1)

class CGPHardwareGELU(HardwareLUTActivation):
    def __init__(self, csv_filename: str = "cgp_results2.csv"):
        super().__init__(csv_filename=csv_filename, column_idx=2)

class CGPHardwareTanhexp(HardwareLUTActivation):
    def __init__(self, csv_filename: str = "cgp_results2.csv"):
        super().__init__(csv_filename=csv_filename, column_idx=3)

# ==========================================
# 3. POLYNOMIAL APPROXIMATION DEFINITIONS (Kim et al.)
# ==========================================
class PolyApproxSwishTanhexp(nn.Module):
    """Kim et al. Polynomial Approximation for Swish and Tanhexp (K2 = 4.0)"""
    def forward(self, x: Tensor) -> Tensor:
        neg_poly = (x * torch.pow(x + 4.0, 2)) / 32.0
        # torch.where(condition, value_if_true, value_if_false)
        return torch.where(x < -4.0, 0.0, torch.where(x < 0.0, neg_poly, x))

class PolyApproxGELU(nn.Module):
    """Kim et al. Polynomial Approximation for GELU (K2 = 3.0)"""
    def forward(self, x: Tensor) -> Tensor:
        neg_poly = (x * torch.pow(x + 3.0, 2)) / 32.0
        return torch.where(x < -3.0, 0.0, torch.where(x < 0.0, neg_poly, x))


# ==========================================
# 4. RESNET ARCHITECTURE DEFINITIONS
# ==========================================
def conv3x3(in_planes: int, out_planes: int, stride: int = 1, groups: int = 1, dilation: int = 1) -> nn.Conv2d:
    return nn.Conv2d(in_planes, out_planes, kernel_size=3, stride=stride, padding=dilation, groups=groups, bias=False, dilation=dilation)

def conv1x1(in_planes: int, out_planes: int, stride: int = 1) -> nn.Conv2d:
    return nn.Conv2d(in_planes, out_planes, kernel_size=1, stride=stride, bias=False)


class BasicBlock(nn.Module):
    expansion: int = 1

    def __init__(
        self,
        inplanes: int,
        planes: int,
        stride: int = 1,
        downsample: Optional[nn.Module] = None,
        groups: int = 1,
        base_width: int = 64,
        dilation: int = 1,
        norm_layer: Optional[Callable[..., nn.Module]] = None,
        act_layer: Optional[Callable[..., nn.Module]] = None,
    ) -> None:
        super().__init__()
        if norm_layer is None:
            norm_layer = nn.BatchNorm2d
        if act_layer is None:
            act_layer = nn.ReLU
            
        self.conv1 = conv3x3(inplanes, planes, stride)
        self.bn1 = norm_layer(planes)
        self.act1 = act_layer()
        self.conv2 = conv3x3(planes, planes)
        self.bn2 = norm_layer(planes)
        self.act2 = act_layer()
        self.downsample = downsample
        self.stride = stride

    def forward(self, x: Tensor) -> Tensor:
        identity = x

        out = self.conv1(x)
        out = self.bn1(out)
        out = self.act1(out)

        out = self.conv2(out)
        out = self.bn2(out)

        if self.downsample is not None:
            identity = self.downsample(x)

        out += identity
        out = self.act2(out)

        return out


class ResNet(nn.Module):
    def __init__(
        self,
        block: type[Union[BasicBlock]],
        layers: list[int],
        num_classes: int = 100,
        zero_init_residual: bool = False,
        groups: int = 1,
        width_per_group: int = 64,
        replace_stride_with_dilation: Optional[list[bool]] = None,
        norm_layer: Optional[Callable[..., nn.Module]] = None,
        act_layer: Optional[Callable[..., nn.Module]] = None,
        cifar_stem: bool = True,
    ) -> None:
        super().__init__()
        if norm_layer is None:
            norm_layer = nn.BatchNorm2d
        if act_layer is None:
            act_layer = nn.ReLU
            
        self._norm_layer = norm_layer
        self._act_layer = act_layer

        self.inplanes = 64
        self.dilation = 1
        if replace_stride_with_dilation is None:
            replace_stride_with_dilation = [False, False, False]

        self.groups = groups
        self.base_width = width_per_group

        if cifar_stem:
            self.conv1 = nn.Conv2d(3, self.inplanes, kernel_size=3, stride=1, padding=1, bias=False)
            self.maxpool = nn.Identity()
        else:
            self.conv1 = nn.Conv2d(3, self.inplanes, kernel_size=7, stride=2, padding=3, bias=False)
            self.maxpool = nn.MaxPool2d(kernel_size=3, stride=2, padding=1)

        self.bn1 = norm_layer(self.inplanes)
        self.act1 = act_layer()

        self.layer1 = self._make_layer(block, 64, layers[0])
        self.layer2 = self._make_layer(block, 128, layers[1], stride=2, dilate=replace_stride_with_dilation[0])
        self.layer3 = self._make_layer(block, 256, layers[2], stride=2, dilate=replace_stride_with_dilation[1])
        self.layer4 = self._make_layer(block, 512, layers[3], stride=2, dilate=replace_stride_with_dilation[2])
        self.avgpool = nn.AdaptiveAvgPool2d((1, 1))
        self.fc = nn.Linear(512 * block.expansion, num_classes)

        for m in self.modules():
            if isinstance(m, nn.Conv2d):
                nn.init.kaiming_normal_(m.weight, mode="fan_out", nonlinearity="relu")
            elif isinstance(m, (nn.BatchNorm2d, nn.GroupNorm)):
                nn.init.constant_(m.weight, 1)
                nn.init.constant_(m.bias, 0)

    def _make_layer(
        self,
        block: type[Union[BasicBlock]],
        planes: int,
        blocks: int,
        stride: int = 1,
        dilate: bool = False,
    ) -> nn.Sequential:
        norm_layer = self._norm_layer
        act_layer = self._act_layer
        downsample = None
        previous_dilation = self.dilation
        if dilate:
            self.dilation *= stride
            stride = 1
        if stride != 1 or self.inplanes != planes * block.expansion:
            downsample = nn.Sequential(
                conv1x1(self.inplanes, planes * block.expansion, stride),
                norm_layer(planes * block.expansion),
            )

        layers = []
        layers.append(
            block(
                self.inplanes, planes, stride, downsample, self.groups, self.base_width, previous_dilation, norm_layer, act_layer
            )
        )
        self.inplanes = planes * block.expansion
        for _ in range(1, blocks):
            layers.append(
                block(
                    self.inplanes,
                    planes,
                    groups=self.groups,
                    base_width=self.base_width,
                    dilation=self.dilation,
                    norm_layer=norm_layer,
                    act_layer=act_layer,
                )
            )

        return nn.Sequential(*layers)

    def forward(self, x: Tensor) -> Tensor:
        x = self.conv1(x)
        x = self.bn1(x)
        x = self.act1(x)
        x = self.maxpool(x)

        x = self.layer1(x)
        x = self.layer2(x)
        x = self.layer3(x)
        x = self.layer4(x)

        x = self.avgpool(x)
        x = torch.flatten(x, 1)
        x = self.fc(x)

        return x


# ==========================================
# 5. METRIC CALCULATION
# ==========================================
def accuracy(output, target, topk=(1, 5)):
    with torch.no_grad():
        maxk = max(topk)
        batch_size = target.size(0)

        _, pred = output.topk(maxk, 1, True, True)
        pred = pred.t()
        correct = pred.eq(target.view(1, -1).expand_as(pred))

        res = []
        for k in topk:
            correct_k = correct[:k].reshape(-1).float().sum(0, keepdim=True)
            res.append(correct_k.mul_(100.0 / batch_size).item())
        return res


# ==========================================
# 6. MAIN BENCHMARK TRAINING LOOP
# ==========================================
def main():
    parser = argparse.ArgumentParser(description="CIFAR-100 ResNet Benchmark")
    parser.add_argument("--act", type=str, default="Tanhexp", choices=[
        "Tanhexp", "HardwareTanhexp", "PolyTanhexp", "CGPTanhexp",
        "SiLU", "HardwareSwish", "PolySwish", "CGPSwish",
        "GELU", "HardwareGELU", "PolyGELU", "CGPGELU",
        "ReLU"
    ])
    parser.add_argument("--batch_size", type=int, default=128)
    args = parser.parse_args()

    # Mapping Activations
    act_map = {
        "Tanhexp": Tanhexp, 
        "HardwareTanhexp": HardwareTanhexp,
        "PolyTanhexp": PolyApproxSwishTanhexp,
        "CGPTanhexp": CGPHardwareTanhexp,
        "SiLU": nn.SiLU, 
        "HardwareSwish": HardwareSwish,
        "PolySwish": PolyApproxSwishTanhexp,
        "CGPSwish": CGPHardwareSwish,
        "GELU": nn.GELU, 
        "HardwareGELU": HardwareGELU,
        "PolyGELU": PolyApproxGELU,
        "CGPGELU": CGPHardwareGELU,
        "ReLU": nn.ReLU
    }
    selected_act = act_map[args.act]

    # Setup Logging
    log_dir = "./logs_cifar100"
    os.makedirs(log_dir, exist_ok=True)
    log_file_path = os.path.join(log_dir, f"log_resnet18_{args.act}.txt")
    log_file = open(log_file_path, "w")

    def print_log(msg):
        print(msg)
        log_file.write(msg + "\n")
        log_file.flush()

    print_log(f"==================================================")
    print_log(f" MODEL: ResNet-18 | ACTIVATION: {args.act} | DATASET: CIFAR-100")
    print_log(f" BATCH SIZE: {args.batch_size}")
    print_log(f"==================================================")

    device = torch.device("cuda" if torch.cuda.is_available() else "cpu")
    print_log(f"Using device: {device}")

    # Standard CIFAR-100 Normalization
    transform_train = transforms.Compose([
        transforms.RandomCrop(32, padding=4),
        transforms.RandomHorizontalFlip(),
        transforms.ToTensor(),
        transforms.Normalize((0.5071, 0.4867, 0.4408), (0.2675, 0.2565, 0.2761)),
    ])

    transform_test = transforms.Compose([
        transforms.ToTensor(),
        transforms.Normalize((0.5071, 0.4867, 0.4408), (0.2675, 0.2565, 0.2761)),
    ])

    trainset = torchvision.datasets.CIFAR100(root='./data', train=True, download=True, transform=transform_train)
    trainloader = DataLoader(trainset, batch_size=args.batch_size, shuffle=True, num_workers=2)

    testset = torchvision.datasets.CIFAR100(root='./data', train=False, download=True, transform=transform_test)
    testloader = DataLoader(testset, batch_size=args.batch_size, shuffle=False, num_workers=2)

    model = ResNet(BasicBlock, [2, 2, 2, 2], num_classes=100, act_layer=selected_act, cifar_stem=True)
    model = model.to(device)

    criterion = nn.CrossEntropyLoss()
    
    # Adjust learning rate if using a smaller batch size (e.g. 64 instead of 128)
    lr = 0.1 if args.batch_size >= 128 else 0.05
    optimizer = optim.SGD(model.parameters(), lr=lr, momentum=0.9, weight_decay=5e-4)
    epochs = 200
    scheduler = optim.lr_scheduler.CosineAnnealingLR(optimizer, T_max=epochs)

    print_log("\n--- Starting Training ---")
    for epoch in range(1, epochs + 1):
        model.train()
        running_loss = 0.0
        for inputs, targets in trainloader:
            inputs, targets = inputs.to(device), targets.to(device)

            optimizer.zero_grad()
            outputs = model(inputs)
            loss = criterion(outputs, targets)
            loss.backward()
            optimizer.step()

            running_loss += loss.item()

        scheduler.step()

        model.eval()
        top1_sum, top5_sum, total_samples = 0.0, 0.0, 0
        with torch.no_grad():
            for inputs, targets in testloader:
                inputs, targets = inputs.to(device), targets.to(device)
                outputs = model(inputs)

                top1, top5 = accuracy(outputs, targets, topk=(1, 5))
                batch_size = targets.size(0)

                top1_sum += top1 * batch_size
                top5_sum += top5 * batch_size
                total_samples += batch_size

        epoch_top1 = top1_sum / total_samples
        epoch_top5 = top5_sum / total_samples

        print_log(f"Epoch [{epoch}/{epochs}] - Loss: {running_loss/len(trainloader):.4f} | "
                  f"Test Top-1 Acc: {epoch_top1:.2f}% | Test Top-5 Acc: {epoch_top5:.2f}%")

    log_file.close()

if __name__ == "__main__":
    main()
