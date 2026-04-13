# -*- coding: utf-8 -*-
"""
Create Date Time : 2025/12/21 16:21
Create User : 19410
Desc : Bert模型的使用Demo

NOTE:
    默认情况下，会下载到当前用户根目录下的.cache/huggingface文件夹中
    但是可以通过给定环境变量:
        XDG_CACHE_HOME=xxx 来指定模型保存文件路径

# pip install transformers==4.57.3 -i https://mirrors.aliyun.com/pypi/simple
# 由于transformers框架对应的网站 https://huggingface.co 需要外网访问，所以这里弄一个国内使用的网站
# 国内网站：https://hf-mirror.com   --- 有做访问限制的处理

"""

import os

import torch

# os.environ['HF_ENDPOINT'] = 'https://hf-mirror.com'
os.environ['XDG_CACHE_HOME'] = r"D:\cache"
os.environ['CACHE_HOME'] = r'D:\cache'


def tt_v0():
    from transformers import AutoTokenizer, AutoModelForMaskedLM, AutoModel, BertModel

    tokenizer = AutoTokenizer.from_pretrained("bert-base-chinese")
    print(f"Bert对应的分词器:\n{type(tokenizer)}\n{tokenizer}\n")
    model = BertModel.from_pretrained("bert-base-chinese")
    print(f"Bert对应的模型:\n{type(model)}\n{model}\n")


def tt_v1():
    from transformers import pipeline

    unmasker = pipeline('fill-mask', model='bert-base-chinese')
    print("=" * 50)
    print(unmasker("The man worked as a [MASK]."))
    print("=" * 50)
    print(unmasker("The woman worked as a [MASK]."))
    print("=" * 50)
    print(unmasker("中国的首都是[MASK]京。"))


def tt_v2():
    from transformers import BertTokenizer, BertModel, BertConfig
    from transformers.modeling_outputs import BaseModelOutputWithPoolingAndCrossAttentions

    tokenizer = BertTokenizer.from_pretrained('bert-base-chinese')
    model = BertModel.from_pretrained("bert-base-chinese")
    text = "还有双鸭山到淮阴的汽车票吗13号的"
    # 基于给定文本得到文本对应的分词结果以及token id转换结果
    # encoded_input = tokenizer(text, return_tensors='pt')
    encoded_input = tokenizer([text, "从这里怎么回家"], return_tensors='pt', padding=True)
    # 将token id输入模型得到模型输出：默认仅包括bert最后一层的输出特征向量
    output = model(**encoded_input)
    print(type(output))
    # 获取bert模型最后一层的输出特征向量 [bs,t,hidden_size]
    last_hidden_state = output[0]  # output.last_hidden_state
    print(last_hidden_state.shape)
    cls_hidden_state = last_hidden_state[:, 0, :]  # 获取CLS这个token对应的特征向量
    print(cls_hidden_state.shape)


def tt_v3():
    from transformers import BertConfig, BertModel

    config = BertConfig(
        vocab_size=1000,
        hidden_size=128,
        num_hidden_layers=2,
        num_attention_heads=4,
        intermediate_size=512,
        hidden_act="gelu",
        hidden_dropout_prob=0.1,
        attention_probs_dropout_prob=0.1,
        max_position_embeddings=512,
        type_vocab_size=2,
        initializer_range=0.02,
        layer_norm_eps=1e-12,
        pad_token_id=0,
        position_embedding_type="absolute",
        use_cache=True,
        classifier_dropout=None,
    )
    model = BertModel(config=config, add_pooling_layer=False)

    bert_output = model(
        input_ids=torch.tensor([
            [101, 25, 36, 12, 102, 0, 0],
            [101, 5, 8, 9, 32, 58, 102]
        ]),
        attention_mask=torch.tensor([
            [1, 1, 1, 1, 1, 0, 0],
            [1, 1, 1, 1, 1, 1, 1]
        ]),
        encoder_hidden_states=None,
        encoder_attention_mask=None,
        past_key_values=None,
        use_cache=None,
        output_attentions=True,  # 期望返回attention的权重列表
        output_hidden_states=True  # 期望返回各个层的输出特征向量
    )
    print(type(bert_output))
    """
    bert_output中的参数: ---> 以dict形式返回的时候
        last_hidden_state: Optional[torch.FloatTensor] = None 最后一层的特征向量
        pooler_output: Optional[torch.FloatTensor] = None CLS对应位置的全连接特征向量
        hidden_states: Optional[tuple[torch.FloatTensor, ...]] = None 所有层的特征向量
        past_key_values: Optional[Cache] = None 需要缓存的key/value信息 -- 解码器生效
        attentions: Optional[tuple[torch.FloatTensor, ...]] = None self attention计算出来的相关性矩阵
        cross_attentions: Optional[tuple[torch.FloatTensor, ...]] = None encoder-decoder cross attention计算出来的相关性矩阵
    """


def tt_v4():
    from transformers import BertConfig, BertModel

    config = BertConfig(
        vocab_size=1000,
        hidden_size=128,
        num_hidden_layers=2,
        num_attention_heads=4,
        intermediate_size=512,
        hidden_act="gelu",
        hidden_dropout_prob=0.1,
        attention_probs_dropout_prob=0.1,
        max_position_embeddings=512,
        type_vocab_size=2,
        initializer_range=0.02,
        layer_norm_eps=1e-12,
        pad_token_id=0,
        position_embedding_type="absolute",
        use_cache=True,
        classifier_dropout=None,
        is_decoder=True  # 当前创建模型是一个解码器结构 -- 只有解码器，没有编码器的结构
    )
    model = BertModel(config=config, add_pooling_layer=False)

    bert_output = model(
        input_ids=torch.tensor([
            [101, 25, 36, 12, 102, 0, 0],
            [101, 5, 8, 9, 32, 58, 102]
        ]),
        attention_mask=torch.tensor([
            [1, 1, 1, 1, 1, 0, 0],
            [1, 1, 1, 1, 1, 1, 1]
        ]),
        encoder_hidden_states=None,
        encoder_attention_mask=None,
        past_key_values=None,
        use_cache=True,
        output_attentions=True,  # 期望返回attention的权重列表
        output_hidden_states=True  # 期望返回各个层的输出特征向量
    )
    print(type(bert_output))
    """
    bert_output中的参数: ---> 以dict形式返回的时候
        last_hidden_state: Optional[torch.FloatTensor] = None 最后一层的特征向量
        pooler_output: Optional[torch.FloatTensor] = None CLS对应位置的全连接特征向量
        hidden_states: Optional[tuple[torch.FloatTensor, ...]] = None 所有层的特征向量
        past_key_values: Optional[Cache] = None 需要缓存的key/value信息 -- 解码器生效
        attentions: Optional[tuple[torch.FloatTensor, ...]] = None self attention计算出来的相关性矩阵
        cross_attentions: Optional[tuple[torch.FloatTensor, ...]] = None encoder-decoder cross attention计算出来的相关性矩阵
    """

    bert_output = model(
        input_ids=torch.tensor([
            [0],
            [135]
        ]),
        attention_mask=torch.tensor([
            [0],
            [1]
        ]),
        encoder_hidden_states=None,
        encoder_attention_mask=None,
        past_key_values=bert_output.past_key_values,  # 将上一次输出的缓存key/value再一次输入
        use_cache=True,
        output_attentions=True,  # 期望返回attention的权重列表
        output_hidden_states=True  # 期望返回各个层的输出特征向量
    )
    print(type(bert_output))


if __name__ == '__main__':
    tt_v4()
