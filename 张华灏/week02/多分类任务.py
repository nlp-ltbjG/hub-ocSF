import os
os.environ['KMP_DUPLICATE_LIB_OK'] = 'TRUE'
import torch
import torch.nn as nn
import numpy as np
import random
import json
import matplotlib.pyplot as plt

class TorchModel(nn.Module):
    def __init__(self,input_size):
        super(TorchModel, self).__init__()
        self.linear = nn.Linear(input_size,input_size)
        self.activation = torch.softmax
        self.loss=nn.functional.cross_entropy

    def forward(self,x, y=None):
        x=self.linear(x)
        y_pred=self.activation(x,dim=1)
        if y is not None:
            return self.loss(y_pred,y)
        else:
            return y_pred


def build_sample(l):
    x = np.random.random(l)
    y = np.zeros(l)

    idx = np.argmax(x)
    y[idx] = 1

    return x, y


def build_dataset(total_sample_num,l):
    X = []
    Y = []
    for i in range(total_sample_num):
        x,y=build_sample(l)
        X.append(x)
        Y.append(y)

    return torch.FloatTensor(X),torch.FloatTensor(Y)

def evaluate(model,l):
    model.eval()
    test_num=100
    x,y=build_dataset(test_num,l)
    correct, wrong = 0, 0
    with torch.no_grad():
        y_pred = model(x)
        for y_p,y_t in zip(y_pred,y):
            idx_p=np.argmax(y_p)
            idx_t=np.argmax(y_t)
            if idx_p==idx_t:
                correct+=1
            else:
                wrong+=1
    print("正确预测个数：%d, 正确率：%f" % (correct, correct / (correct + wrong)))
    return correct/(correct+wrong)

def main():
    epoch_num = 30
    batch_size = 20
    train_sample = 5000
    input_size = 5
    learning_rate = 0.008

    model = TorchModel(input_size)

    optim = torch.optim.Adam(model.parameters(), lr=learning_rate)
    log=[]

    train_x, train_y = build_dataset(train_sample,input_size)
    for epoch in range(epoch_num):
        model.train()
        watch_loss=[]
        for batch_index in range(train_sample // batch_size):
            x = train_x[batch_index * batch_size: (batch_index + 1) * batch_size]
            y = train_y[batch_index * batch_size: (batch_index + 1) * batch_size]
            loss = model(x,y)
            loss.backward()
            optim.step()
            optim.zero_grad()
            watch_loss.append(loss.item())
        print("=========\n第%d轮平均loss:%f" % (epoch + 1, np.mean(watch_loss)))
        acc = evaluate(model,input_size)
        log.append([acc, float(np.mean(watch_loss))])
    torch.save(model.state_dict(), "model.bin")
    # 画图
    print(log)
    plt.plot(range(len(log)), [l[0] for l in log], label="acc")  # 画acc曲线
    plt.plot(range(len(log)), [l[1] for l in log], label="loss")  # 画loss曲线
    plt.legend()
    plt.show()
    return


def predict(model_path, input_vec):
    input_size = 5
    model = TorchModel(input_size)
    model.load_state_dict(torch.load(model_path))
    print(model.state_dict())

    model.eval()
    with torch.no_grad():
        result = model(torch.FloatTensor(input_vec))

    for vec, res in zip(input_vec, result):
        pred = torch.argmax(res).item()
        prob = res[pred].item()
        print("输入：%s, 预测类别：%d, 概率值：%.6f" % (vec, pred, prob))



if __name__ == "__main__":
    main()
    test_vec = [[0.88889086, 0.15229675, 0.31082123, 0.03504317, 0.88920843],
                [0.94963533,0.5524256,0.95758807,0.95520434,0.84890681],
                [0.90797868,0.67482528,0.13625847,0.34675372,0.19871392],
                 [0.99349776,0.59416669,0.92579291,0.41567412,0.1358894]]
    predict("model.bin", test_vec)
