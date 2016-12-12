
#!/usr/bin/env python

"""
Usage example employing Lasagne for digit recognition using the MNIST dataset.

This example is deliberately structured as a long flat file, focusing on how
to use Lasagne, instead of focusing on writing maximally modular and reusable
code. It is used as the foundation for the introductory Lasagne tutorial:
http://lasagne.readthedocs.org/en/latest/user/tutorial.html

More in-depth examples and reproductions of paper results are maintained in
a separate repository: https://github.com/Lasagne/Recipes
"""

from __future__ import print_function

import sys
import os
import time

import numpy as np
import theano
import theano.tensor as T

import lasagne

# ################## Download and prepare the MNIST dataset ##################
# This is just some way of getting the MNIST dataset from an online location
# and loading it into numpy arrays. It doesn't involve Lasagne at all.

def load_dataset():
    # We first define a download function, supporting both Python 2 and 3.
    if sys.version_info[0] == 2:
        from urllib import urlretrieve
    else:
        from urllib.request import urlretrieve

    def download(filename, source='http://yann.lecun.com/exdb/mnist/'):
        print("Downloading %s" % filename)
        urlretrieve(source + filename, filename)

    # We then define functions for loading MNIST images and labels.
    # For convenience, they also download the requested files if needed.
    import gzip

    def load_mnist_images(filename):
        if not os.path.exists(filename):
            download(filename)
        # Read the inputs in Yann LeCun's binary format.
        with gzip.open(filename, 'rb') as f:
            data = np.frombuffer(f.read(), np.uint8, offset=16)
        # The inputs are vectors now, we reshape them to monochrome 2D images,
        # following the shape convention: (examples, channels, rows, columns)
        data = data.reshape(-1, 1, 28, 28)
        # The inputs come as bytes, we convert them to float32 in range [0,1].
        # (Actually to range [0, 255/256], for compatibility to the version
        # provided at http://deeplearning.net/data/mnist/mnist.pkl.gz.)
        return data / np.float32(256)

    def load_mnist_labels(filename):
        if not os.path.exists(filename):
            download(filename)
        # Read the labels in Yann LeCun's binary format.
        with gzip.open(filename, 'rb') as f:
            data = np.frombuffer(f.read(), np.uint8, offset=8)
        # The labels are vectors of integers now, that's exactly what we want.
        return data

    # We can now download and read the training and test set images and labels.
    X_train = load_mnist_images('train-images-idx3-ubyte.gz')
    y_train = load_mnist_labels('train-labels-idx1-ubyte.gz')
    X_test = load_mnist_images('t10k-images-idx3-ubyte.gz')
    y_test = load_mnist_labels('t10k-labels-idx1-ubyte.gz')

    # We reserve the last 10000 training examples for validation.
    X_train, X_val = X_train[:-10000], X_train[-10000:]
    y_train, y_val = y_train[:-10000], y_train[-10000:]

    # We just return all the arrays in order, as expected in main().
    # (It doesn't matter how we do this as long as we can read them again.)
    return X_train, y_train, X_val, y_val, X_test, y_test

def build_cnn(input_var=None, nfilters = 32):
    # As a third model, we'll create a CNN of two convolution + pooling stages
    # and a fully-connected hidden layer in front of the output layer.

    # Input layer, as usual:
    network = lasagne.layers.InputLayer(shape=(None, 1, 28, 28),
                                        input_var=input_var)
    # This time we do not apply input dropout, as it tends to work less well
    # for convolutional layers.

    # Convolutional layer with 32 kernels of size 5x5. Strided and padded
    # convolutions are supported as well; see the docstring.
    network = lasagne.layers.Conv2DLayer(
            network, num_filters=nfilters, filter_size=(5, 5),
            nonlinearity=lasagne.nonlinearities.rectify,
            W=lasagne.init.GlorotUniform())
    # Expert note: Lasagne provides alternative convolutional layers that
    # override Theano's choice of which implementation to use; for details
    # please see http://lasagne.readthedocs.org/en/latest/user/tutorial.html.

    # Max-pooling layer of factor 2 in both dimensions:
    network = lasagne.layers.MaxPool2DLayer(network, pool_size=(2, 2))

    # Another convolution with 32 5x5 kernels, and another 2x2 pooling:
    network = lasagne.layers.Conv2DLayer(
            network, num_filters=nfilters, filter_size=(5, 5),
            nonlinearity=lasagne.nonlinearities.rectify)
    network = lasagne.layers.MaxPool2DLayer(network, pool_size=(2, 2))

    # A fully-connected layer of 256 units with 50% dropout on its inputs:
    network = lasagne.layers.DenseLayer(
            lasagne.layers.dropout(network, p=.5),
            num_units=256,
            nonlinearity=lasagne.nonlinearities.rectify)

    # And, finally, the 10-unit output layer with 50% dropout on its inputs:
    network = lasagne.layers.DenseLayer(
            lasagne.layers.dropout(network, p=.5),
            num_units=10,
            nonlinearity=lasagne.nonlinearities.softmax)

    return network


# ############################# Batch iterator ###############################
# This is just a simple helper function iterating over training data in
# mini-batches of a particular size, optionally in random order. It assumes
# data is available as numpy arrays. For big datasets, you could load numpy
# arrays as memory-mapped files (np.load(..., mmap_mode='r')), or write your
# own custom data iteration function. For small datasets, you can also copy
# them to GPU at once for slightly improved performance. This would involve
# several changes in the main program, though, and is not demonstrated here.
# Notice that this function returns only mini-batches of size `batchsize`.
# If the size of the data is not a multiple of `batchsize`, it will not
# return the last (remaining) mini-batch.

def iterate_minibatches(inputs, targets, batchsize, shuffle=False):
    assert len(inputs) == len(targets)
    if shuffle:
        indices = np.arange(len(inputs))
        np.random.shuffle(indices)
    for start_idx in range(0, len(inputs) - batchsize + 1, batchsize):
        if shuffle:
            excerpt = indices[start_idx:start_idx + batchsize]
        else:
            excerpt = slice(start_idx, start_idx + batchsize)
        yield inputs[excerpt], targets[excerpt]


# ############################## Main program ################################
# Everything else will be handled in our main program now. We could pull out
# more functions to better separate the code, but it wouldn't make it any
# easier to read.

def main(ntrain = 50000, nvalid = 10000, ntest = 10000, algorithm_type = 1,
         batch_size_train = 500, batch_size_valid = 500, batch_size_test = 500,
         num_epochs=500, stat_filename = 'stat.txt', LR = 0.1, M = 0.9,
         nfilters = 32, time_limit = 10000):
    # Load the dataset
    print("Loading data...")
    X_train, y_train, X_val, y_val, X_test, y_test = load_dataset()

    X_train = X_train[1:ntrain]
    y_train = y_train[1:ntrain]
    X_val = X_val[1:nvalid]
    y_val = y_val[1:nvalid]
    X_test = X_test[1:ntest]
    y_test = y_test[1:ntest]

    # Prepare Theano variables for inputs and targets
    input_var = T.tensor4('inputs')
    target_var = T.ivector('targets')

    # Create neural network model (depending on first command line parameter)
    print("Building model and compiling functions...")
    network = build_cnn(input_var, nfilters)

    # Create a loss expression for training, i.e., a scalar objective we want
    # to minimize (for our multi-class problem, it is the cross-entropy loss):
    prediction = lasagne.layers.get_output(network)
    loss = lasagne.objectives.categorical_crossentropy(prediction, target_var)
    loss = loss.mean()
    # We could add some weight decay as well here, see lasagne.regularization.

    # Create update expressions for training, i.e., how to modify the
    # parameters at each training step. Here, we'll use Stochastic Gradient
    # Descent (SGD) with Nesterov momentum, but Lasagne offers plenty more.
    params = lasagne.layers.get_all_params(network, trainable=True)
    if (algorithm_type == 1):
        updates = lasagne.updates.sgd(loss, params, learning_rate=LR)
    if (algorithm_type == 2):
        updates = lasagne.updates.momentum(loss, params, learning_rate=LR,
                                           momentum = M)

    # Create a loss expression for validation/testing. The crucial difference
    # here is that we do a deterministic forward pass through the network,
    # disabling dropout layers.
    test_prediction = lasagne.layers.get_output(network, deterministic=True)
    test_loss = lasagne.objectives.categorical_crossentropy(test_prediction,
                                                            target_var)
    test_loss = test_loss.mean()
    # As a bonus, also create an expression for the classification accuracy:
    test_acc = T.mean(T.eq(T.argmax(test_prediction, axis=1), target_var),
                      dtype=theano.config.floatX)

    # Compile a function performing a training step on a mini-batch (by giving
    # the updates dictionary) and returning the corresponding training loss:
    train_fn = theano.function([input_var, target_var], loss, updates=updates)

    # Compile a second function computing the validation loss and accuracy:
    val_fn = theano.function([input_var, target_var], [test_loss, test_acc])

    # Finally, launch the training loop.
    nparameters = lasagne.layers.count_params(network, trainable=True)
    print("Number of parameters in model: {}".format(nparameters))
    print("Starting training...")

    stat_file = open(stat_filename, 'w+', 0)
    start_time = time.time()

    best_val_acc = 0

    # We iterate over epochs:
    for epoch in range(num_epochs):
        # In each epoch, we do a full pass over the training data:
        train_err = 0
        train_batches = 0
        start_time_epoch = time.time()
        for batch in iterate_minibatches(X_train, y_train, batch_size_train, shuffle=True):
            inputs, targets = batch
            train_err += train_fn(inputs, targets)
            train_batches += 1

        # And a full pass over the validation data:
        val_err = 0
        val_acc = 0
        val_batches = 0
        for batch in iterate_minibatches(X_val, y_val, batch_size_valid, shuffle=False):
            inputs, targets = batch
            err, acc = val_fn(inputs, targets)
            val_err += err
            val_acc += acc
            val_batches += 1

        # Then we print the results for this epoch:
        print("Epoch {} of {} took {:.3f}s".format(
            epoch + 1, num_epochs, time.time() - start_time_epoch))
        print("  training loss:\t\t{:.6f}".format(train_err / train_batches))
        print("  validation loss:\t\t{:.6f}".format(val_err / val_batches))
        print("  validation accuracy:\t\t{:.2f} %".format(
            val_acc / val_batches * 100))

        if (val_acc / val_batches * 100 > best_val_acc):
            best_val_acc = val_acc / val_batches * 100

        stat_file.write("{}\t{:.15g}\t{:.15g}\t{:.15g}\t{:.15g}\n".format(
            epoch, time.time() - start_time, train_err / train_batches,
            val_err / val_batches, val_acc / val_batches * 100))

        if (time.time() - start_time > time_limit):
            break

    # After training, we compute and print the test error:
    test_err = 0
    test_acc = 0
    test_batches = 0
    for batch in iterate_minibatches(X_test, y_test, batch_size_test, shuffle=False):
        inputs, targets = batch
        err, acc = val_fn(inputs, targets)
        test_err += err
        test_acc += acc
        test_batches += 1
    print("Final results:")
    print("  test loss:\t\t\t{:.6f}".format(test_err / test_batches))
    print("  test accuracy:\t\t{:.2f} %".format(
        test_acc / test_batches * 100))

    stat_file.close()

    return [best_val_acc, time.time()-start_time, nparameters]

    # Optionally, you could now dump the network weights to a file like this:
    # np.savez('model.npz', *lasagne.layers.get_all_param_values(network))
    #
    # And load them again later on like this:
    # with np.load('model.npz') as f:
    #     param_values = [f['arr_%d' % i] for i in range(len(f.files))]
    # lasagne.layers.set_all_param_values(network, param_values)


if __name__ == '__main__':

    ntrain = 50000              # number of training examples
    nvalid = 10000              # number of validation examples
    ntest = 10000               # number of test examples
    batch_size_train = 500      # batch size used for training
    batch_size_valid = 500      # batch size used for validation
    batch_size_test = 500       # batch size used for testing
    algorithm_type = 1          # 1 - SGD, 2 - SGD with momentum

    M = 0.9                     # momentum factor for SGD with momentum
    nfilters = 32               # number of convolutional filters in each layer
    time_limit = 10000          # .. seconds, huge value to disable this option

    iscenario = 5

    if (iscenario == 1):
        ntrain = 5000           # reduce the size of the training set by a factor of 10 to save 10x time
        nvalid = 1000           # same here
        ntest = 1000            # same here
        num_epochs = 50

        for irun in [1, 2, 3]:              # independent runs
            for LR in [0.001, 0.01, 0.1, 0.2, 0.5, 1.0, 2.0]:     # different settings for learning rate LR of SGD
                stat_filename = "stat_{}_{}_{}.txt".format(iscenario, irun, int(LR*1000))
                main(ntrain, nvalid, ntest, algorithm_type, batch_size_train,
                     batch_size_valid, batch_size_test, num_epochs, stat_filename, LR, M, nfilters, time_limit)

    if (iscenario == 2):
        ntrain = 5000           # reduce the size of the training set by a factor of 10 to save 10x time
        nvalid = 1000           # same here
        ntest = 1000            # same here
        num_epochs = 50

        irun = 1                # one run only
        for batch_size_train in [20, 100, 500]:         # different settings for batch size of SGD
            for LR in [0.1, 0.2, 0.5]:                  # different settings for learning rate LR of SGD
                batch_size_valid = batch_size_train
                stat_filename = "stat_{}_{}_{}_{}.txt".format(iscenario, irun, int(LR * 1000), batch_size_train)
                main(ntrain, nvalid, ntest, algorithm_type, batch_size_train,
                     batch_size_valid, batch_size_test, num_epochs, stat_filename, LR, M, nfilters, time_limit)

    if (iscenario == 3):
        ntrain = 5000           # reduce the size of the training set by a factor of 10 to save 10x time
        nvalid = 1000           # same here
        ntest = 1000            # same here
        batch_size_train = 64   # this value should work better than 1 or 1000, but by no means it is optimal
        batch_size_valid = 500  # does not influence training process, but reduces time loss from validation
        batch_size_test = 500   # same here
        num_epochs = 50

        algorithm_type = 2      # SGD with momentum
        irun = 1                # one run only
        for M in [0, 0.5, 0.9]:                         # different settings for momentum factor M of SGD
            for LR in [0.001, 0.01, 0.1]:               # different settings for learning rate LR of SGD
                stat_filename = "stat_{}_{}_{}_{}.txt".format(iscenario, irun, int(LR * 1000), int(M * 1000))
                main(ntrain, nvalid, ntest, algorithm_type, batch_size_train,
                     batch_size_valid, batch_size_test, num_epochs, stat_filename, LR, M, nfilters, time_limit)

    if (iscenario == 4):
        ntrain = 5000           # reduce the size of the training set by a factor of 10 to save 10x time
        nvalid = 1000           # same here
        ntest = 1000            # same here
        batch_size_train = 64   # this value should work better than 1 or 1000, but by no means it is optimal
        batch_size_valid = 500  # does not influence training process, but reduces time loss from validation
        batch_size_test = 500   # same here
        num_epochs = 50

        algorithm_type = 2      # SGD with momentum
        M = 0.5                 # whatever
        LR = 0.1                # same here
        irun = 1                # one run only
        for nfilters in [1, 2, 4, 8, 16, 32, 64, 128, 256]: # different settings for the number if filters per layer
            stat_filename = "stat_{}_{}_{}.txt".format(iscenario, irun, nfilters)
            main(ntrain, nvalid, ntest, algorithm_type, batch_size_train,
                batch_size_valid, batch_size_test, num_epochs, stat_filename, LR, M, nfilters, time_limit)

    if (iscenario == 5):
        ntrain = 50000          # the whole training set
        nvalid = 10000          #
        ntest = 10000           #
        batch_size_valid = 500  # does not influence training process, but reduces time loss from validation
        batch_size_test = 500   # same here
        num_epochs = 100000     # to disable this stopping criterion
        time_limit = 60         # training time is limited to 60 seconds

        algorithm_type = 2  # SGD with momentum
        irun = 1  # one run only
        mexevaluations = 200
        nvariables = 4
        solutions_filename = "solutions_{}_{}.txt".format(iscenario, irun)
        solutions_file = open(solutions_filename, 'w+', 0)
        for ievaluation in range(0, mexevaluations):
            x = np.random.rand(nvariables)
            nfilters = 10 + int(90*x[0])                        #   in [10, 100]
            batch_size_train = int(pow(2.0, 4.0 + 4.0*x[1]))    #   in [2^4, 2^8] = [16, 256]
            M = float(x[2])                                     #   in [0, 1]
            LR = float(pow(10.0, -2 + 1.5*x[3]))                #   in [10^-2, 10^-0.5] = [0.01, ~0.31]

            print("nfilters: {}\tbatch_size_train: {}\t M: {:.6f}\t LR: {:.6f}".format(
                    nfilters, batch_size_train, M, LR))

            stat_filename = "stat_{}_{}_{}.txt".format(iscenario, irun, ievaluation)
            results = main(ntrain, nvalid, ntest, algorithm_type, batch_size_train,
                 batch_size_valid, batch_size_test, num_epochs, stat_filename, LR, M, nfilters, time_limit)

            solutions_file.write("{:.15g}\t{:.15g}\t{:.15g}\t{:.15g}\t".format(
                                    float(nfilters), float(batch_size_train), M, LR))

            best_val_acc = results[0]
            total_time = results[1]
            nparameters = float(results[2])
            solutions_file.write("{:.15g}\t{:.15g}\t{:.15g}\n".format(best_val_acc,total_time,nparameters))

        solutions_file.close()


