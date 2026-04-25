import os
import torch
import torch_mlu

# import torch_mlu.core.mlu_model as ct
import torch.nn as nn
import time
from PIL import Image
from torchvision import transforms

torch.set_grad_enabled(False)
# ct.set_device(0)
_ = torch_mlu
cfgs = [
    64,
    "R",
    64,
    "R",
    "M",
    128,
    "R",
    128,
    "R",
    "M",
    256,
    "R",
    256,
    "R",
    256,
    "R",
    256,
    "R",
    "M",
    512,
    "R",
    512,
    "R",
    512,
    "R",
    512,
    "R",
    "M",
    512,
    "R",
    512,
    "R",
    512,
    "R",
    512,
    "R",
    "M",
]

IMAGE_PATH = "data/strawberries.jpg"
VGG_PATH = "models/vgg19.pth"
BASE_DIR = os.path.dirname(os.path.abspath(__file__))
PROJECT_DIR = os.path.dirname(BASE_DIR)


def vgg19():
    layers = [
        "conv1_1",
        "relu1_1",
        "conv1_2",
        "relu1_2",
        "pool1",
        "conv2_1",
        "relu2_1",
        "conv2_2",
        "relu2_2",
        "pool2",
        "conv3_1",
        "relu3_1",
        "conv3_2",
        "relu3_2",
        "conv3_3",
        "relu3_3",
        "conv3_4",
        "relu3_4",
        "pool3",
        "conv4_1",
        "relu4_1",
        "conv4_2",
        "relu4_2",
        "conv4_3",
        "relu4_3",
        "conv4_4",
        "relu4_4",
        "pool4",
        "conv5_1",
        "relu5_1",
        "conv5_2",
        "relu5_2",
        "conv5_3",
        "relu5_3",
        "conv5_4",
        "relu5_4",
        "pool5",
        "flatten",
        "fc6",
        "relu6",
        "fc7",
        "relu7",
        "fc8",
        "softmax",
    ]
    layer_container = nn.Sequential()
    in_channels = 3
    num_classes = 1000
    conv_channels = [
        64,
        64,
        128,
        128,
        256,
        256,
        256,
        256,
        512,
        512,
        512,
        512,
        512,
        512,
        512,
        512,
    ]
    conv_idx = 0
    for i, layer_name in enumerate(layers):
        if layer_name.startswith("conv"):
            # 填充：卷积层
            layer_container.add_module(
                layer_name,
                nn.Conv2d(
                    in_channels=in_channels,
                    out_channels=conv_channels[conv_idx],
                    kernel_size=3,
                    padding=1,
                ),
            )
            in_channels = conv_channels[conv_idx]
            conv_idx += 1
        elif layer_name.startswith("relu"):
            # 填充：ReLU 激活层
            layer_container.add_module(layer_name, nn.ReLU(inplace=True))
        elif layer_name.startswith("pool"):
            # 填充：最大池化层
            layer_container.add_module(
                layer_name, nn.MaxPool2d(kernel_size=2, stride=2)
            )
        elif layer_name == "flatten":
            # 填充：展平层
            layer_container.add_module(layer_name, nn.Flatten())
        elif layer_name == "fc6":
            # 填充：全连接层 fc6
            layer_container.add_module(layer_name, nn.Linear(25088, 4096))
        elif layer_name == "fc7":
            # 填充：全连接层 fc7
            layer_container.add_module(layer_name, nn.Linear(4096, 4096))
        elif layer_name == "fc8":
            # 填充：全连接层 fc8
            layer_container.add_module(layer_name, nn.Linear(4096, num_classes))
        elif layer_name == "softmax":
            # 填充：Softmax 输出层
            layer_container.add_module(layer_name, nn.Softmax(dim=1))
    return layer_container


def load_image(path):
    # 填充：读取输入图像
    image = Image.open(path).convert("RGB")
    transform = transforms.Compose(
        [
            transforms.Resize(256),
            transforms.CenterCrop(224),
            transforms.ToTensor(),
            transforms.Normalize(mean=[0.485, 0.456, 0.406], std=[0.229, 0.224, 0.225]),
        ]
    )
    # 填充：图像预处理
    image = transform(image)
    # 填充：扩展 batch 维度
    image = image.unsqueeze(0)
    return image


if __name__ == "__main__":
    # 1. read image
    # 填充：按脚本相对路径加载图像
    input_image = load_image(os.path.join(PROJECT_DIR, IMAGE_PATH))
    # 2. load model
    # TODO: 生成VGG19网络模型
    net = vgg19()
    # TODO: 加载网络参数到net中
    net.load_state_dict(
        torch.load(os.path.join(PROJECT_DIR, VGG_PATH), map_location="cpu")
    )
    # 3. Put our model in eval mode
    # TODO: 模型进入推理模式
    net.eval()
    # 4. jit.trace
    example_forward_input = torch.rand((1, 3, 224, 224), dtype=torch.float)
    # 5. image and model to mlu
    # 填充：将动态图转化为静态图
    net_traced = torch.jit.trace(net, example_forward_input)
    # 填充：将输入图像拷贝到 MLU 设备
    input_image = input_image.to("mlu")
    # 填充：将 traced model 拷贝到 MLU 设备
    net_traced = net_traced.to("mlu")
    # 6. inference
    st = time.time()
    # 填充：进行推理
    prob = net_traced(input_image)
    print("mlu370<cnnl backend> infer time:{:.3f} s".format(time.time() - st))
    # 填充：将结果从 MLU 拷贝回 CPU
    prob = prob.to("cpu")
    with open(os.path.join(PROJECT_DIR, "labels", "imagenet_classes.txt")) as f:
        classes = [line.strip() for line in f.readlines()]
        _, indices = torch.sort(prob, descending=True)
    print(
        "Classification result: id = %s, prob = %f "
        % (classes[indices[0][0]], prob[0][indices[0][0]].item())
    )
    if classes[indices[0][0]] == "strawberry":
        print("TEST RESULT PASS.")
    else:
        print("TEST RESULT FAILED.")
