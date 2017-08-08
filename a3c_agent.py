import numpy as np
import tensorflow as tf
import tensorflow.contrib.slim as slim
import scipy.signal

from random import choice


# Copies one set of variables to another.
# Used to set worker network parameters to those of global network.
def update_target_graph(from_scope,to_scope):
    from_vars = tf.get_collection(tf.GraphKeys.TRAINABLE_VARIABLES, from_scope)
    to_vars = tf.get_collection(tf.GraphKeys.TRAINABLE_VARIABLES, to_scope)

    op_holder = []
    for from_var,to_var in zip(from_vars,to_vars):
        op_holder.append(to_var.assign(from_var))
    return op_holder

# Discounting function used to calculate discounted returns.
def discount(x, gamma):
    return scipy.signal.lfilter([1], [1, -gamma], x[::-1], axis=0)[::-1]

#Used to initialize weights for policy and value output layers
def normalized_columns_initializer(std=1.0):
    def _initializer(shape, dtype=None, partition_info=None):
        out = np.random.randn(*shape).astype(np.float32)
        out *= std / np.sqrt(np.square(out).sum(axis=0, keepdims=True))
        return tf.constant(out)
    return _initializer



class AC_Network():
    def __init__(self, s_size, a_size, scope, trainer):
        with tf.variable_scope(scope):
            #Input and visual encoding layers
            self.inputs = tf.placeholder(shape=[None, s_size], dtype=tf.float32)

            # self.laser = tf.slice(self.inputs, [0, 0], [-1, 180])
            # self.path = tf.slice(self.inputs, [0, 180], [-1, 2])

            # # process laser
            # laser_reshape = tf.reshape(self.laser,shape=[-1, 180, 1]) 
            # conv1 = tf.layers.conv1d(   inputs=laser_reshape,
            #                             filters=16,
            #                             kernel_size=8,
            #                             padding="valid",
            #                             activation=tf.nn.relu,
            #                             name = 'laser_conv1')
            # conv2 = tf.layers.conv1d(   inputs=conv1,
            #                             filters=32,
            #                             kernel_size=4,
            #                             padding="valid",
            #                             activation=tf.nn.relu,
            #                             name = 'laser_conv2')
            # # self.conv1 = slim.conv2d(activation_fn=tf.nn.elu,
            # #     inputs=laser_reshape, num_outputs=16,
            # #     kernel_size=[8,8], stride=[1,1], padding='VALID')
            # # self.conv2 = slim.conv2d(activation_fn=tf.nn.elu,
            # #     inputs=self.conv1,num_outputs=32,
            # #     kernel_size=[4,4],stride=[2,2],padding='VALID')

            # conv_flat = tf.contrib.layers.flatten(conv2)

            # process target
            path_reshape = tf.reshape(self.inputs, [-1, 2])
            path_fc = tf.layers.dense(inputs=path_reshape, units=64, activation=tf.nn.relu, name = 'target_fc1')
            # path_fc2 = tf.layers.dense(inputs=path_fc, units=32, activation=tf.nn.relu, name = 'target_fc2')

            # # concat laser and target
            # concat_feature = tf.concat([conv_flat, path_fc], 1, name = 'base_laser_path_concat')
            # concat_fc = tf.layers.dense(inputs=path_fc, units=32, activation=tf.nn.relu, name = 'concat_fc1')

            # Output layers for policy and value estimations
            self.policy = tf.layers.dense(inputs=path_fc, units=a_size, name = 'policy',
                activation=tf.nn.softmax,
                kernel_initializer=normalized_columns_initializer(0.01),
                bias_initializer=None)
            self.value = tf.layers.dense(inputs=path_fc, units=1, name = 'value',
                activation=None,
                kernel_initializer=normalized_columns_initializer(1.0),
                bias_initializer=None)


            # fc1 = slim.fully_connected(path_reshape, 32, 
            #     activation_fn=tf.nn.relu)
            # concat_fc = slim.fully_connected(fc1, 32,
            #     activation_fn=tf.nn.relu)

            # self.policy = slim.fully_connected(concat_fc, a_size, 
            #     activation_fn=tf.nn.softmax,
            #     weights_initializer=normalized_columns_initializer(0.01),
            #     biases_initializer=None)
            # self.value = slim.fully_connected(concat_fc, 1,
            #     activation_fn=None,
            #     weights_initializer=normalized_columns_initializer(1.0),
            #     biases_initializer=None)
            
            #Only the worker network need ops for loss functions and gradient updating.
            if scope != 'global':
                self.actions = tf.placeholder(shape=[None],dtype=tf.int32)
                self.actions_onehot = tf.one_hot(self.actions,a_size,dtype=tf.float32)
                self.target_v = tf.placeholder(shape=[None],dtype=tf.float32)
                self.advantages = tf.placeholder(shape=[None],dtype=tf.float32)

                self.responsible_outputs = tf.reduce_sum(self.policy * self.actions_onehot, [1])

                #Loss functions
                self.value_loss = 0.5 * tf.reduce_sum(tf.square(self.target_v - tf.reshape(self.value,[-1])))
                self.entropy = - tf.reduce_sum(self.policy * tf.log(self.policy))
                self.policy_loss = -tf.reduce_sum(tf.log(self.responsible_outputs)*self.advantages)
                self.loss = 0.5 * self.value_loss + self.policy_loss - self.entropy * 0.01

                #Get gradients from local network using local losses
                local_vars = tf.get_collection(tf.GraphKeys.TRAINABLE_VARIABLES, scope)
                self.gradients = tf.gradients(self.loss,local_vars)
                self.var_norms = tf.global_norm(local_vars)
                grads,self.grad_norms = tf.clip_by_global_norm(self.gradients,40.0)
                
                #Apply local gradients to global network
                global_vars = tf.get_collection(tf.GraphKeys.TRAINABLE_VARIABLES, 'global')
                self.apply_grads = trainer.apply_gradients(zip(grads,global_vars))

class Worker():
    def __init__(self, env, name, s_size, a_size, trainer, model_path, global_episodes):
        self.name = "worker_" + str(name)
        self.number = name        
        self.model_path = model_path
        self.trainer = trainer
        self.global_episodes = global_episodes
        self.increment = self.global_episodes.assign_add(1)
        self.episode_rewards = []
        self.episode_lengths = []
        self.episode_mean_values = []
        # self.summary_writer = tf.summary.FileWriter("train_"+str(self.number))

        #Create the local copy of the network and the tensorflow op to copy global paramters to local network
        self.local_AC = AC_Network(s_size,a_size,self.name,trainer)
        self.update_local_ops = update_target_graph('global',self.name)        
        
        self.actions = np.identity(a_size,dtype=bool).tolist()
        self.env = env
        
    def train(self, rollout, sess, gamma, bootstrap_value):
        rollout = np.array(rollout)
        observations = rollout[:,0]
        actions = rollout[:,1]
        rewards = rollout[:,2]
        next_observations = rollout[:,3]       
        values = rollout[:,5] # should be 5 with next_observation
        
        # Here we take the rewards and values from the rollout, and use them to 
        # generate the advantage and discounted returns. 
        # The advantage function uses "Generalized Advantage Estimation"
        self.rewards_plus = np.asarray(rewards.tolist() + [bootstrap_value])
        discounted_rewards = discount(self.rewards_plus, gamma)[:-1]
        self.value_plus = np.asarray(values.tolist() + [bootstrap_value])
        advantages = rewards + gamma * self.value_plus[1:] - self.value_plus[:-1]
        advantages = discount(advantages, gamma)

        # Update the global network using gradients from loss
        # Generate network statistics to periodically save
        feed_dict = {self.local_AC.target_v:discounted_rewards,
            self.local_AC.inputs:np.vstack(observations),
            self.local_AC.actions:actions,
            self.local_AC.advantages:advantages}
        v_l,p_l,e_l,g_n,v_n,_ = sess.run([self.local_AC.value_loss,
            self.local_AC.policy_loss,
            self.local_AC.entropy,
            self.local_AC.grad_norms,
            self.local_AC.var_norms,
            self.local_AC.apply_grads],
            feed_dict=feed_dict)

        print (np.mean(discounted_rewards))
        return v_l/len(rollout), p_l/len(rollout), e_l/len(rollout), g_n, v_n, np.mean(discounted_rewards)
        
    def work(self, max_episode_length, env, sess, summary_writer, coord, saver):
        episode_count = sess.run(self.global_episodes)
        total_steps = 0
        print ("Starting worker " + str(self.number))
        with sess.as_default(), sess.graph.as_default():                 
            while not coord.should_stop():
                sess.run(self.update_local_ops)
                episode_buffer = []
                episode_values = []
                episode_frames = []
                episode_reward = 0
                episode_step_count = 0
                d = False
                
                s = self.env.reset()
                episode_frames.append(s)
                
                while episode_step_count < max_episode_length:     # one ep
                    #Take an action using probabilities from policy network output.
                    a_dist, v = sess.run([self.local_AC.policy, self.local_AC.value], 
                        feed_dict={self.local_AC.inputs:[s]})
                    a = np.random.choice(a_dist[0],p=a_dist[0])
                    a = np.argmax(a_dist == a)

                    s1, r, d, _ = self.env.step(a)

                    if d == False:
                        episode_frames.append(s1)
                    else:
                        s1 = s
                        
                    episode_buffer.append([s,a,r,s1,d,v[0,0]])       
                    # episode_buffer.append([s, a, r, d, v[0,0]]) 
                    episode_values.append(v[0,0])

                    episode_reward += r
                    s = s1                    
                    total_steps += 1
                    episode_step_count += 1
                    
                    # If the episode hasn't ended, but the experience buffer is full, then we
                    # make an update step using that experience rollout.
                    if len(episode_buffer) == 500 and d != True and episode_step_count != max_episode_length - 1:        # batch size and ep length!!!!!!
                        # Since we don't know what the true final return is, we "bootstrap" from our current
                        # value estimation.
                        v1 = sess.run(self.local_AC.value,   
                            feed_dict={self.local_AC.inputs:[s]})[0,0]
                        v_l,p_l,e_l,g_n,v_n, return_n = self.train(episode_buffer,sess,gamma,v1)
                        episode_buffer = []
                        sess.run(self.update_local_ops)
        
                    if d == True:
                        break
                                            
                self.episode_rewards.append(episode_reward)
                self.episode_lengths.append(episode_step_count)
                self.episode_mean_values.append(np.mean(episode_values))
                
                # Update the network using the experience buffer at the end of the episode.
                if len(episode_buffer) != 0:
                    v_l, p_l, e_l, g_n, v_n, return_n = self.train(episode_buffer, sess, env, 0.0)                              
                    
                # Periodically save gifs of episodes, model parameters, and summary statistics.
                if episode_count % 10 == 0 and episode_count != 0:
                    # if self.name == 'worker_0' and episode_count % 25 == 0:
                    #     time_per_step = 0.05
                    #     images = np.array(episode_frames)
                    #     make_gif(images,'./frames/image'+str(episode_count)+'.gif',
                    #         duration=len(images)*time_per_step,true_image=True,salience=False)
                    # if episode_count % 250 == 0 and self.name == 'worker_0':
                        # saver.save(sess,self.model_path+'/model-'+str(episode_count)+'.cptk')       
                    saver.save(sess, self.model_path+'/model.cptk')   
                    print ("Saved Model")

                if self.name == 'worker_0':
                    sess.run(self.increment)
                    
                    mean_reward = np.mean(self.episode_rewards[-5:])
                    mean_length = np.mean(self.episode_lengths[-5:])
                    mean_value = np.mean(self.episode_mean_values[-5:])
                    summary = tf.Summary()
                    summary.value.add(tag='Perf/Reward', simple_value=float(mean_reward))
                    summary.value.add(tag='Perf/Length', simple_value=float(mean_length))
                    summary.value.add(tag='Perf/Value', simple_value=float(mean_value))
                    summary.value.add(tag='Perf/average Return', simple_value=float(return_n))
                    summary.value.add(tag='Losses/Value Loss', simple_value=float(v_l))
                    summary.value.add(tag='Losses/Policy Loss', simple_value=float(p_l))
                    summary.value.add(tag='Losses/Entropy', simple_value=float(e_l))
                    summary.value.add(tag='Losses/Grad Norm', simple_value=float(g_n))
                    summary.value.add(tag='Losses/Var Norm', simple_value=float(v_n))
                    summary_writer.add_summary(summary, episode_count)

                    summary_writer.flush()  

                episode_count += 1


