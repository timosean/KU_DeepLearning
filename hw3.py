import sys
import os
import matplotlib.pyplot as plt
import numpy as np

class nn_linear_layer:
    
    # linear layer.
    # randomly initialized by creating matrix W and bias b
    # 처음에 넣을 때 input_size 2, output_size 4로 넣으심
    # 두 번째로 넣을 때 input_size 4, output_size 2로 넣으심
    def __init__(self, input_size, output_size, std=1):
        self.W = np.random.normal(0,std,(output_size,input_size)) #1st shape: 4*2   /   2nd shape: 2*4
        self.b = np.random.normal(0,std,(output_size,1)) #1st shape: 4*1    /   2nd shape: 2*1
    
    ######
    ## Q1
    ## output: Wx+b, Shape: (B,O), where B is batch size, and O is output dimension
    def forward(self,x):       
        ret = (self.W)@(x.T) + self.b
        # print("ret의 shape: ", ret.shape)
        return ret.T
    
    ######
    ## Q2
    ## returns three parameters: dLdx, dLdW, dLdb
    ## dLdy: upstream gradient coming from the next layer.
    ## need to return the gradients, which will be passed as the upstream gradient to the previous layer.
    ## dLdW = dLdy * dydW
    ## dLdb = dLdy * dydb
    def backprop(self,x,dLdy):
        # print("dLdy의 차원: ", dLdy.shape)
        # print("x의 차원: ", x.shape)
        # print("W의 차원: ", self.W.shape)
        
        dLdW = dLdy.T@(x)
        dLdx = dLdy@(self.W)
        dLdb = np.sum(dLdy, axis=0)
        return dLdW,dLdb,dLdx

    def update_weights(self,dLdW,dLdb):

        # parameter update
        self.W=self.W+dLdW
        self.b=self.b+dLdb.reshape(self.b.size, 1)

class nn_activation_layer:
    
    def __init__(self):
        pass
    
    def sigmoid(self, x):
        return 1 / (1 +np.exp(-x))
    
    ######
    ## Q3
    ## input parameter: x, Shape(20, 4)
    ## returns sigmoid(x) elementwise. Thus, output shape is (B,I)
    def forward(self,x):
        ret = np.zeros_like(x)
        ret = self.sigmoid(x)
        
        # for i in range(0, 20):
        #     tmp = self.sigmoid(np.transpose(x[i]).reshape(4,1))
        #     ret[i] = np.transpose(tmp)
            
        return ret
    
    ######
    ## Q4
    ## dLdy: upstream gradient coming from the next layer.
    ## y denotes the output of this layer.
    ## need to return the following gradient dLdx = dLdy * dydx, which will passed as the upstream gradient
    ## to the previous layer.
    def backprop(self,x,dLdy):
        # print("x의 차원: ", x.shape)
        # print("dLdy의 차원: ", dLdy.shape)
        
        dydx = (1-self.sigmoid(x))*(self.sigmoid(x))
        
        # for i in range(0, 20):
        #     dydx[i] = (1-self.sigmoid(x[i]))*(self.sigmoid(x[i]))
            
        return dLdy*dydx


class nn_softmax_layer:
    def __init__(self):
        pass
    
    
    def softmax(self, x):
        ret = np.exp(x) / np.sum(np.exp(x), axis=1, keepdims=True)
        return ret
    
    ######
    ## Q5
    ## input x의 Shape: (20, 2)
    ## Returns softmax(x), Shape: (20, 2)
    def forward(self,x):
        ret = self.softmax(x)
        
        # for i in range(0, 20):
        #     tmp = self.softmax(x[i])
        #     ret[i] = tmp
            
        return ret
    
    ######
    ## Q6
    ## Returns dLdx = dLdy * dydx
    ## dLdy is the upstream gradient coming from the next layer.
    ## y denotes the output of this layer.
    def backprop(self,x,dLdy):
        # dydx = np.zeros((20,2))
        
        # sftmx = self.softmax(x)
        # dydx = sftmx * (1 - sftmx)
        
        # # for i in range(0, 20):
        # #     dydx[i][0] = sftmx[0] * (1-sftmx[0])
        # #     dydx[i][1] = sftmx[1] * (1-sftmx[1])
        
        # ret = dLdy * dydx
        return dLdy

class nn_cross_entropy_layer:
    def __init__(self):
        pass
    
    def cross_entropy_loss(self, x, y):
        ret = 0
        
        for i in range(0, y.size):
            temp = y[i] * np.log(x[i][0]) + (1 - y[i]) * np.log(1 - x[i][0])
            ret += temp
        
        ret = -(ret/y.size)
        return ret
        
    ######
    ## Q7
    ## returns the cross-entropy loss defined in Equation(1) (과제pdf에 있음)
    ## x: input to this layer. Shape(20 ,2)
    ## y: ground truth labels. Shape(20, 1)
    def forward(self,x,y):
        return self.cross_entropy_loss(x, y)
        
    ######
    ## Q8
    ## returns dLdx. Has the same shape as x
    ## x: input to this layer. Shape: (B,I)
    ## y: ground truth labels. Shape: (B,1)
    ## B: batch size / I: input feature dimension
    def backprop(self,x,y):
        y = y.reshape(-1)
        one_hot = np.zeros((y.size, y.max() + 1))
        one_hot[np.arange(y.size), y] = 1

        loss = x-one_hot
        
        return loss

# number of data points for each of (0,0), (0,1), (1,0) and (1,1)
num_d=5

# number of test runs
num_test=40

## Q9. Hyperparameter setting
## learning rate (lr)and number of gradient descent steps (num_gd_step)
## This part is not graded (there is no definitive answer).
## You can set this hyperparameters through experiments.
lr=0.05
num_gd_step=10000

# dataset size
batch_size=4*num_d

# number of classes is 2
num_class=2

# variable to measure accuracy
accuracy=0

# set this True if want to plot training data
show_train_data=True

# set this True if want to plot loss over gradient descent iteration
show_loss=True

################
# create training data
################

m_d1 = (0, 0)
m_d2 = (1, 1)
m_d3 = (0, 1)
m_d4 = (1, 0)

sig = 0.05
s_d1 = sig ** 2 * np.eye(2)

d1 = np.random.multivariate_normal(m_d1, s_d1, num_d)
d2 = np.random.multivariate_normal(m_d2, s_d1, num_d)
d3 = np.random.multivariate_normal(m_d3, s_d1, num_d)
d4 = np.random.multivariate_normal(m_d4, s_d1, num_d)

# training data, and has shape (4*num_d,2)
x_train_d = np.vstack((d1, d2, d3, d4))
# training data lables, and has shape (4*num_d,1)
y_train_d = np.vstack((np.zeros((2 * num_d, 1), dtype='uint8'), np.ones((2 * num_d, 1), dtype='uint8')))

if (show_train_data):
    plt.grid()
    plt.scatter(x_train_d[range(2 * num_d), 0], x_train_d[range(2 * num_d), 1], color='b', marker='o')
    plt.scatter(x_train_d[range(2 * num_d, 4 * num_d), 0], x_train_d[range(2 * num_d, 4 * num_d), 1], color='r',
                marker='x')
    plt.show()

################
# create layers
################

# hidden layer
# linear layer
layer1 = nn_linear_layer(input_size=2, output_size=4, )
# activation layer
act = nn_activation_layer()

# output layer
# linear
layer2 = nn_linear_layer(input_size=4, output_size=2, )
# softmax
smax = nn_softmax_layer()
# cross entropy
cent = nn_cross_entropy_layer()

# variable for plotting loss
loss_out = np.zeros((num_gd_step))

################
# do training
################

for i in range(num_gd_step):
    
    # fetch data
    x_train = x_train_d
    y_train = y_train_d
    
    # create one-hot vectors from the ground truth labels
    y_onehot = np.zeros((batch_size, num_class))
    y_onehot[range(batch_size), y_train.reshape(batch_size, )] = 1
    
    ################
    # forward pass
    
    # hidden layer
    # linear
    l1_out = layer1.forward(x_train)
    # activation
    a1_out = act.forward(l1_out)
    
    # output layer
    # linear
    l2_out = layer2.forward(a1_out)
    # softmax
    smax_out = smax.forward(l2_out)
    # cross entropy loss
    loss_out[i] = cent.forward(smax_out, y_train)
    
    ################
    # perform backprop
    # output layer
    # cross entropy
    b_cent_out = cent.backprop(smax_out, y_train)
    # softmax
    b_nce_smax_out = smax.backprop(l2_out, b_cent_out)
    
    # linear
    b_dLdW_2, b_dLdb_2, b_dLdx_2 = layer2.backprop(x=a1_out, dLdy=b_nce_smax_out)
    
    # backprop, hidden layer
    # activation
    b_act_out = act.backprop(x=l1_out, dLdy=b_dLdx_2)
    # linear
    b_dLdW_1, b_dLdb_1, b_dLdx_1 = layer1.backprop(x=x_train, dLdy=b_act_out)
    
    ################
    # update weights: perform gradient descent
    layer2.update_weights(dLdW=-b_dLdW_2 * lr, dLdb=-b_dLdb_2.T * lr)
    layer1.update_weights(dLdW=-b_dLdW_1 * lr, dLdb=-b_dLdb_1.T * lr)
    
    if (i + 1) % 2000 == 0:
        print('gradient descent iteration:', i + 1)

# set show_loss to True to plot the loss over gradient descent iterations
if (show_loss):
    plt.figure(1)
    plt.grid()
    plt.plot(range(num_gd_step), loss_out)
    plt.xlabel('number of gradient descent steps')
    plt.ylabel('cross entropy loss')
    plt.show()

################
# training done
# now testing

num_test = 100

for j in range(num_test):
    
    predicted = np.ones((4,))
    
    # dispersion of test data
    sig_t = 1e-2
    
    # generate test data
    # generate 4 samples, each sample nearby (1,1), (0,0), (1,0), (0,1) respectively
    t11 = np.random.multivariate_normal((1,1), sig_t**2*np.eye(2), 1)
    t00 = np.random.multivariate_normal((0,0), sig_t**2*np.eye(2), 1)
    t10 = np.random.multivariate_normal((1,0), sig_t**2*np.eye(2), 1)
    t01 = np.random.multivariate_normal((0,1), sig_t**2*np.eye(2), 1)
    
    # predicting label for test sample nearby (1,1)
    l1_out = layer1.forward(t11)
    a1_out = act.forward(l1_out)
    l2_out = layer2.forward(a1_out)
    smax_out = smax.forward(l2_out)
    predicted[0] = np.argmax(smax_out)
    print('softmax out for (1,1)', smax_out, 'predicted label:', int(predicted[0]))
    
    # predicting label for test sample nearby (0,0)
    l1_out = layer1.forward(t00)
    a1_out = act.forward(l1_out)
    l2_out = layer2.forward(a1_out)
    smax_out = smax.forward(l2_out)
    predicted[1] = np.argmax(smax_out)
    print('softmax out for (0,0)', smax_out, 'predicted label:', int(predicted[1]))
    
    # predicting label for test sample nearby (1,0)
    l1_out = layer1.forward(t10)
    a1_out = act.forward(l1_out)
    l2_out = layer2.forward(a1_out)
    smax_out = smax.forward(l2_out)
    predicted[2] = np.argmax(smax_out)
    print('softmax out for (1,0)', smax_out, 'predicted label:', int(predicted[2]))
    
    # predicting label for test sample nearby (0,1)
    l1_out = layer1.forward(t01)
    a1_out = act.forward(l1_out)
    l2_out = layer2.forward(a1_out)
    smax_out = smax.forward(l2_out)
    predicted[3] = np.argmax(smax_out)
    print('softmax out for (0,1)', smax_out, 'predicted label:', int(predicted[3]))
    
    print('total predicted labels:', predicted.astype('uint8'))
    
    accuracy += (predicted[0] == 0) & (predicted[1] == 0) & (predicted[2] == 1) & (predicted[3] == 1)
    
    if (j + 1) % 10 == 0:
        print('test iteration:', j + 1)

print('accuracy:', accuracy / num_test * 100, '%')






