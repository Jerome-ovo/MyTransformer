# MyTransformer
This is a Transformer architecture that uses the PyTorch framework to replicate the paper "Attention is All You Need", hoping to provide some help for beginners.

这是一个使用PyTorch框架复制论文《Attention is All You Need》的Transformer架构，希望能为初学者提供一些帮助。

The various parts of the model construction have been annotated in Chinese, so you can delve into the model and explore how the transformer model works.

模型搭建的各个部分已经使用中文注释清楚，使用大家可以深入模型内部以探究transformer模型是如何运转的。

I copied a diagram of the transformer model architecture as follows:

我临摹了一张transformer模型的架构图，如下所示：

![transformer architecture](/transformer.png)

Development environment:
  torch.version  1.11.0
  cuda           11.3

Since I'm not using a visual component or a package like torchvision, torchaudio, but based on pytorch itself, the ambient pytorch version should have little impact. But a reminder to all beginners: remember to use the GPU.

因为我没有使用诸如可视化组件或像torchvision, torchaudio这样的包，而是基于pytorch本身，所以环境pytorch版本应该影响不大。不过提醒各位新手：记得使用GPU。

Tips: Both the dataset (wmt14) and tokenizer used in this project can be downloaded from the Internet (e.g., from Hugging Face, etc.).

提示：本项目中使用的数据集（wmt14）和tokenizer都可以从网上（比如从Hugging Face等）下载到。

Wish you all the best!

祝您顺利！
